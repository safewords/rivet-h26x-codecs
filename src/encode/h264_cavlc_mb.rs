//! The CAVLC intra macroblock layer: [`MbDecision`]s into bits.
//!
//! This is the writing half of a coded intra macroblock, and its single
//! rule is that it mirrors `h264::cavlc::parse_mb_cavlc` element for
//! element: the same syntax order, the same `nC` derivation, the same
//! coded-block-pattern mapping. Wherever the reader owns a table, this
//! side derives its inverse from that table rather than writing the
//! numbers down a second time — two copies of Table 9-4 would be two
//! places for one of them to be wrong, and the round-trip test below
//! asserts the derivation rather than trusting it.
//!
//! The state the reader keeps per picture — the nonzero-coefficient
//! counts its `nC` predictor reads from the left and upper neighbours —
//! is kept here too, in `NzState`, and it is fed from what
//! `write_residual_block_cavlc` *returns* rather than from the mode
//! decision's own counts. The two agree (a `debug_assert` says so where
//! the spans line up), but the returned value is what the reader will
//! store, so it is the one that cannot drift.
//!
//! One asymmetry with the reader is worth naming: the reader derives a
//! neighbouring block's intra prediction mode as DC (2) when the
//! neighbouring macroblock is available but not `I_NxN` (8.3.1.1). The
//! caller's `left_modes` / `top_modes` bookkeeping in
//! [`write_intra_picture`] therefore records `Some(2)` for an available
//! `I_16x16` neighbour — `None` is only ever "no macroblock there".
//! Recording `None` instead would predict DC where the reader predicts
//! `min(2, other)`, and the desync would surface as a wrong decoded mode
//! two macroblocks later.

use crate::bitwriter::BitWriter;
use crate::encode::h264_intra::{MbDecision, MbKind};
use crate::encode::h264_me::{BDecision, BMbKind, InterDecision, InterMbKind};
use crate::encode::h264_pic::{
    BMb, CodedPair, Colocated, IntraTools, PMb, PairMb, PairWriter, PicMotion, code_b_picture,
    code_intra_picture, code_p_picture,
};
use crate::encode::h264_syntax::{Geometry, Plane, Recon};
use crate::h264::cavlc::{
    SCAN_CHROMA_DC, SCAN8_SUB, SCAN8_SUB_FIELD, part_index_of, write_residual_block_cavlc,
};
use crate::h264::mb::MbNeighbours;
use crate::h264::mb::SubMbShape;
use crate::h264::mb::raster_of_blk;
use crate::h264::tables::{
    FIELD_SCAN4X4, GOLOMB_TO_INTER_CBP, GOLOMB_TO_INTER_CBP_GRAY, GOLOMB_TO_INTRA4X4_CBP,
    GOLOMB_TO_INTRA4X4_CBP_GRAY, SCAN_CHROMA_DC_422, ZIGZAG4X4,
};
use crate::sample::Sample;

/// `coded_block_pattern` me(v) for intra: cbp -> codeNum, the inverse of
/// the reader's codeNum -> cbp table, derived from it at compile time.
static INTRA_CBP_TO_GOLOMB: [u8; 48] = {
    let mut inv = [0u8; 48];
    let mut code = 0;
    while code < 48 {
        inv[GOLOMB_TO_INTRA4X4_CBP[code] as usize] = code as u8;
        code += 1;
    }
    inv
};

/// The same for monochrome (and 4:4:4, which this module refuses anyway),
/// whose cbp stops at 15.
static INTRA_CBP_TO_GOLOMB_GRAY: [u8; 16] = {
    let mut inv = [0u8; 16];
    let mut code = 0;
    while code < 16 {
        inv[GOLOMB_TO_INTRA4X4_CBP_GRAY[code] as usize] = code as u8;
        code += 1;
    }
    inv
};

/// `coded_block_pattern` me(v) for inter macroblocks — Table 9-4's other
/// column, inverted from the reader's table like the intra ones above.
static INTER_CBP_TO_GOLOMB: [u8; 48] = {
    let mut inv = [0u8; 48];
    let mut code = 0;
    while code < 48 {
        inv[GOLOMB_TO_INTER_CBP[code] as usize] = code as u8;
        code += 1;
    }
    inv
};

/// See [`INTER_CBP_TO_GOLOMB`]; monochrome.
static INTER_CBP_TO_GOLOMB_GRAY: [u8; 16] = {
    let mut inv = [0u8; 16];
    let mut code = 0;
    while code < 16 {
        inv[GOLOMB_TO_INTER_CBP_GRAY[code] as usize] = code as u8;
        code += 1;
    }
    inv
};

/// The per-picture nonzero-coefficient state `nC` (9.2.1) predicts from:
/// what the reader gathers per macroblock in `MbNeighbours::gather_nz`,
/// kept as one row of counts along the top edge and one column along the
/// left. Updated from the writer's returned `TotalCoeff`s, block by
/// block, exactly when the reader stores them; blocks a cleared cbp bit
/// skips stay zero, which is what the reader's per-macroblock reset
/// leaves behind.
struct NzState {
    /// Per luma-*like* plane (luma; in 4:4:4 also Cb and Cr, which the
    /// reader's `nC` treats as three luma planes — `nb.nz_top` /
    /// `nb.nz_left` in `MbNeighbours::gather_nz`), per 4x4 column of the
    /// picture: the count of the bottom block of the macroblock above
    /// (`mbs_wide * 4`).
    top_luma: [Vec<u8>; 3],
    /// Per luma-like plane and 4x4 row: the count of the rightmost block
    /// of the macroblock to the left.
    left_luma: [[u8; 4]; 3],
    /// The same for the 4:2:x chroma blocks, per component
    /// (`mbs_wide * 2`). Unused in 4:4:4, whose chroma is luma-like.
    top_chroma: [Vec<u8>; 2],
    /// Chroma left column; `rows` entries are meaningful.
    left_chroma: [[u8; 4]; 2],
    /// Chroma AC block rows: 2 (4:2:0), 4 (4:2:2), 0 (monochrome and
    /// 4:4:4 — the latter flagged separately below).
    rows: usize,
    /// ChromaArrayType 3: planes 1 and 2 of the luma-like state are live.
    c444: bool,
    /// The picture is a field: its blocks are read in the field scans —
    /// `FIELD_SCAN4X4` and the field 8x8 sub-scans — which is what
    /// `parse_residual_luma_like` switches to under `ctx.field_pic`.
    field: bool,
}

impl NzState {
    fn new(mbs_wide: usize, rows: usize, c444: bool) -> Self {
        debug_assert!(!c444 || rows == 0, "4:4:4 has no 4:2:x chroma rows");
        NzState {
            top_luma: [
                vec![0; mbs_wide * 4],
                vec![0; mbs_wide * 4],
                vec![0; mbs_wide * 4],
            ],
            left_luma: [[0; 4]; 3],
            top_chroma: [vec![0; mbs_wide * 2], vec![0; mbs_wide * 2]],
            left_chroma: [[0; 4]; 2],
            rows,
            c444,
            field: false,
        }
    }
}

/// The rounded mean of 9.2.1: both neighbours average, one is taken as
/// is, none is zero.
fn nc_of(a: Option<u8>, b: Option<u8>) -> i32 {
    match (a, b) {
        (Some(a), Some(b)) => (a as i32 + b as i32 + 1) >> 1,
        (Some(a), None) => a as i32,
        (None, Some(b)) => b as i32,
        (None, None) => 0,
    }
}

/// A block's levels widened to what the residual writer takes. The reader
/// decodes into `i32`; the decision side stores `i16` because the levels
/// fit and a slice's worth of blocks is measured in kilobytes.
fn widen(levels: &[i16; 16]) -> [i32; 16] {
    let mut out = [0i32; 16];
    for (o, &v) in out.iter_mut().zip(levels) {
        *o = v as i32;
    }
    out
}

/// The chroma DC block widened: four meaningful entries in 4:2:0, eight
/// in 4:2:2. Always eight wide — the writer only reads the scan's span.
fn widen_dc(levels: &[i16; 16]) -> [i32; 8] {
    let mut out = [0i32; 8];
    for (o, &v) in out.iter_mut().zip(levels) {
        *o = v as i32;
    }
    out
}

/// Write one intra macroblock — `mb_type` through the residual — updating
/// `st` with the counts the next macroblocks' `nC` will read. `left` and
/// `top` say whether those neighbouring macroblocks exist.
///
/// `mb_type_offset` is what the slice type adds to an intra `mb_type`
/// before it is coded: 0 in an I slice, 5 in a P slice, 23 in a B slice
/// (Table 7-11's note — the reader subtracts the same constant).
#[allow(clippy::too_many_arguments)]
fn write_macroblock(
    w: &mut BitWriter,
    dec: &MbDecision,
    st: &mut NzState,
    mb_x: usize,
    left: bool,
    top: bool,
    mb_type_offset: u32,
    t8x8_mode: bool,
) {
    let chroma = st.rows != 0;
    let i16x16 = dec.kind == MbKind::I16x16;
    let cbp = (dec.cbp_luma | (dec.cbp_chroma << 4)) as usize;

    // mb_type (Table 7-11): I_NxN is 0 for *both* transform sizes — which
    // is what `transform_size_8x8_flag` below is for; the I_16x16 types
    // encode the prediction mode and both halves of the coded block
    // pattern.
    match dec.kind {
        MbKind::I4x4 | MbKind::I8x8 => w.ue(mb_type_offset),
        MbKind::I16x16 => w.ue(mb_type_offset
            + 1
            + dec.intra16_mode as u32
            + 4 * dec.cbp_chroma as u32
            + 12 * (dec.cbp_luma == 15) as u32),
    }

    // `transform_size_8x8_flag`, before `mb_pred()` and only for I_NxN:
    // the reader takes it under `ctx.transform_8x8_mode && layer.kind ==
    // MbKind::I4x4` (`parse_mb_cavlc` in src/h264/cavlc.rs), where
    // `I4x4` is still standing for I_NxN because the flag has not yet
    // renamed it.
    if t8x8_mode && dec.kind.is_nxn() {
        w.flag(dec.transform_8x8);
    }
    debug_assert!(
        t8x8_mode || !dec.transform_8x8,
        "no PPS flag, no 8x8 transform"
    );

    match dec.kind {
        // The sixteen prediction modes, in luma4x4BlkIdx order — the
        // standard's 4x4 scan, not raster, which is why the raster-indexed
        // decision is walked through `raster_of_blk`.
        MbKind::I4x4 => {
            for blk in 0..16 {
                let p = dec.luma_pred[raster_of_blk(blk)];
                w.flag(p.use_predicted);
                if !p.use_predicted {
                    w.bits(3, p.rem as u32);
                }
            }
        }
        // Four modes instead of sixteen, one per 8x8 quad in raster
        // order, with the same two syntax elements; the decision stored
        // each on all four of its quad's 4x4s, so the quad's top-left is
        // where it is read.
        MbKind::I8x8 => {
            for &raster in &[0usize, 2, 8, 10] {
                let p = dec.luma_pred[raster];
                w.flag(p.use_predicted);
                if !p.use_predicted {
                    w.bits(3, p.rem as u32);
                }
            }
        }
        MbKind::I16x16 => {}
    }
    if chroma {
        w.ue(dec.chroma_mode as u32);
    }
    if dec.kind.is_nxn() {
        // coded_block_pattern as me(v), from the derived inverse mapping.
        let code = if chroma {
            INTRA_CBP_TO_GOLOMB[cbp]
        } else {
            INTRA_CBP_TO_GOLOMB_GRAY[cbp]
        };
        w.ue(code as u32);
    }
    // mb_qp_delta is present exactly when the reader's `has_residual` says
    // so: any coded block, or I_16x16, whose DC block is always coded.
    if cbp != 0 || i16x16 {
        w.se(dec.qp_delta as i32);
    }

    write_mb_residual(
        w,
        st,
        mb_x,
        left,
        top,
        i16x16.then_some(&dec.luma_dc),
        dec.transform_8x8,
        cbp,
        &dec.luma,
        &dec.chroma_dc,
        &dec.chroma_ac,
        &dec.nz_luma,
        &dec.nz_chroma,
    );
}

/// Write one P_L0_16x16 macroblock — `mb_type` through the residual. The
/// skip run before it belongs to the caller, which is counting.
///
/// `sub_mb_type` for a P sub-macroblock (Table 7-17), the inverse of the
/// reader's `p_sub_mb_type` (src/h264/cavlc.rs). `Direct` has no P
/// spelling — it is a B shape — and is refused rather than mis-coded.
pub(crate) fn sub_mb_type_p(shape: SubMbShape) -> u32 {
    match shape {
        SubMbShape::S8x8 => 0,
        SubMbShape::S8x4 => 1,
        SubMbShape::S4x8 => 2,
        SubMbShape::S4x4 => 3,
        SubMbShape::Direct => unreachable!("B_Direct_8x8 is not a P sub-macroblock type"),
    }
}

/// One macroblock of any coded P shape — 16x16, 16x8, 8x16 or 8x8 —
/// since after `mb_type` (and, for 8x8, its four `sub_mb_type`s) they
/// differ only in how many mvds follow.
///
/// No `ref_idx_l0` is written: with exactly one active reference the
/// element is absent from the stream — the reader's `read_ref_idx` is
/// only reached when `num_ref_idx_active > 1` (7.3.5.1) — and this
/// encoder's slice headers always declare one. The `debug_assert` is the
/// tripwire for the day that stops being true.
#[allow(clippy::too_many_arguments)]
fn write_p16_macroblock(
    w: &mut BitWriter,
    dec: &InterDecision,
    st: &mut NzState,
    mb_x: usize,
    left: bool,
    top: bool,
    t8x8_mode: bool,
    ref_idx_zeros: bool,
) {
    debug_assert!(
        !matches!(dec.kind, InterMbKind::PSkip | InterMbKind::UseIntra),
        "only a coded P macroblock carries this syntax"
    );
    debug_assert_eq!(
        dec.ref_idx, 0,
        "more than one reference needs te(v) ref_idx writing"
    );
    w.ue(dec.kind.p_mb_type()); // Table 7-13
    // `P_8x8` first spells its four `sub_mb_type`s (Table 7-17), all of
    // them before any motion — `sub_mb_pred()` is three separate passes
    // over the partitions, and the reader takes them in that order.
    if dec.kind == InterMbKind::P8x8 {
        for part in 0..4 {
            w.ue(sub_mb_type_p(dec.sub_shape[part]));
        }
    }
    // `ref_idx_l0` is absent throughout: one active reference, so the
    // reader infers 0 for every partition (7.3.5.1). That is the second
    // pass, and it has nothing to write — except for a field macroblock of
    // an MBAFF frame, whose list holds each frame's two fields, and whose
    // te(v) index over two entries is one inverted bit (`read_ref_idx`).
    if ref_idx_zeros {
        let parts = if dec.kind == InterMbKind::P8x8 {
            4
        } else {
            dec.kind.parts().len()
        };
        for _ in 0..parts {
            w.te(0, 1);
        }
    }
    //
    // Then one mvd per prediction rectangle, x then y, in syntax order.
    let mut rects = [(0usize, 0usize, 0usize, 0usize); 16];
    let n = dec.rects(&mut rects);
    for &(x, y, _, _) in rects.iter().take(n) {
        let mvd = dec.mvd[(y / 4) * 4 + x / 4];
        w.se(mvd.x as i32);
        w.se(mvd.y as i32);
    }
    let cbp = (dec.cbp_luma | (dec.cbp_chroma << 4)) as usize;
    let code = if st.rows != 0 {
        INTER_CBP_TO_GOLOMB[cbp]
    } else {
        INTER_CBP_TO_GOLOMB_GRAY[cbp]
    };
    w.ue(code as u32);
    // An inter macroblock's `transform_size_8x8_flag` comes after the
    // coded block pattern, only when some luma block is coded, and only
    // when every sub-macroblock partition is at least 8x8 — a `P_8x8`
    // that split any of its four suppresses it (7.3.5).
    if t8x8_mode && dec.cbp_luma != 0 && dec.no_sub_mb_part_less_than_8x8() {
        w.flag(dec.transform_8x8);
    }
    debug_assert!(
        !dec.transform_8x8
            || (t8x8_mode && dec.cbp_luma != 0 && dec.no_sub_mb_part_less_than_8x8())
    );
    // mb_qp_delta is present exactly when the reader's `has_residual` says
    // so, which for an inter macroblock is any coded block at all.
    if cbp != 0 {
        w.se(dec.qp_delta as i32);
    }
    write_mb_residual(
        w,
        st,
        mb_x,
        left,
        top,
        None,
        dec.transform_8x8,
        cbp,
        &dec.luma,
        &dec.chroma_dc,
        &dec.chroma_ac,
        &dec.nz_luma,
        &dec.nz_chroma,
    );
}

/// A skipped macroblock's mark on the `nC` state: every count zero, which
/// is what the reader's per-macroblock reset leaves for its neighbours to
/// read. Forgetting this — leaving the previous coded macroblock's counts
/// in the left column — desyncs the very next residual block's tables.
fn skip_nz(st: &mut NzState, mb_x: usize) {
    for p in 0..3 {
        st.left_luma[p] = [0; 4];
        st.top_luma[p][mb_x * 4..mb_x * 4 + 4].fill(0);
    }
    for comp in 0..2 {
        st.left_chroma[comp] = [0; 4];
        if st.rows != 0 {
            st.top_chroma[comp][mb_x * 2..mb_x * 2 + 2].fill(0);
        }
    }
}

/// One luma-like plane's residual — the DC block for `Intra_16x16`, then
/// the coded 8x8s' 4x4 blocks — with plane `p`'s own `nC` bookkeeping,
/// updated for the next macroblocks. The mirror of
/// `parse_residual_luma_like` (src/h264/cavlc.rs) for one plane: luma is
/// plane 0; in 4:4:4 Cb and Cr are planes 1 and 2 coded the same way,
/// gated by the *same* luma coded-block-pattern bits.
#[allow(clippy::too_many_arguments)]
fn write_plane_residual(
    w: &mut BitWriter,
    st: &mut NzState,
    p: usize,
    mb_x: usize,
    left: bool,
    top: bool,
    dc: Option<&[i16; 16]>,
    transform_8x8: bool,
    cbp: usize,
    levels: &[[i16; 16]; 16],
    nz: &[u8; 16],
) {
    let mut cur = [0u8; 16];
    let (scan4, scan8sub): (&[u8; 16], &[[u8; 16]; 4]) = if st.field {
        (&FIELD_SCAN4X4, &SCAN8_SUB_FIELD)
    } else {
        (&ZIGZAG4X4, &SCAN8_SUB)
    };
    let nc_at = |cur: &[u8; 16], st: &NzState, bx: usize, by: usize| -> i32 {
        let a = if bx > 0 {
            Some(cur[by * 4 + bx - 1])
        } else if left {
            Some(st.left_luma[p][by])
        } else {
            None
        };
        let b = if by > 0 {
            Some(cur[(by - 1) * 4 + bx])
        } else if top {
            Some(st.top_luma[p][mb_x * 4 + bx])
        } else {
            None
        };
        nc_of(a, b)
    };
    if let Some(dc) = dc {
        debug_assert!(
            !transform_8x8,
            "Intra_16x16 carries no transform_size_8x8_flag"
        );
        // The DC block first. Its own count is not stored anywhere — the
        // reader discards it too — so the return is deliberately dropped.
        let nc = nc_at(&cur, st, 0, 0);
        let _ = write_residual_block_cavlc(w, nc, &widen(dc), scan4, 0, 15, 16);
    }
    for blk8 in 0..4 {
        if cbp & (1 << blk8) == 0 {
            continue;
        }
        let (bx8, by8) = ((blk8 & 1) * 2, (blk8 >> 1) * 2);
        // Under the 8x8 transform CAVLC still codes four blocks per 8x8,
        // but they are not its four 4x4s: they are its sixty-four scan
        // positions taken every fourth (`SCAN8_SUB` in src/h264/cavlc.rs,
        // built from `ZIGZAG8X8`), each written as a sixteen-coefficient
        // block into the *8x8*'s storage. Everything else is unchanged —
        // the same four `nC` predictions in the same order, the same
        // counts stored on the same 4x4s — which is exactly why this is a
        // choice of scan and span rather than a second walk.
        let scan8 = transform_8x8.then(|| &levels.as_flattened()[blk8 * 64..blk8 * 64 + 64]);
        for sub in 0..4 {
            let (bx, by) = (bx8 + (sub & 1), by8 + (sub >> 1));
            let raster = by * 4 + bx;
            let nc = nc_at(&cur, st, bx, by);
            let n = if let Some(block8) = scan8 {
                let mut lv = [0i32; 64];
                for (o, &v) in lv.iter_mut().zip(block8) {
                    *o = v as i32;
                }
                write_residual_block_cavlc(w, nc, &lv, &scan8sub[sub], 0, 15, 16)
            } else {
                let lv = widen(&levels[raster]);
                // I_16x16 AC blocks start at scan position one — the DC
                // went in the block above — and so carry at most fifteen.
                if dc.is_some() {
                    write_residual_block_cavlc(w, nc, &lv, scan4, 1, 15, 15)
                } else {
                    write_residual_block_cavlc(w, nc, &lv, scan4, 0, 15, 16)
                }
            };
            debug_assert_eq!(
                n, nz[raster] as usize,
                "plane {p} block ({bx},{by}): the decision's count disagrees with the writer's"
            );
            cur[raster] = n as u8;
        }
    }
    // What the neighbours will read: the right column and the bottom row,
    // including the zeros of blocks nothing coded.
    st.left_luma[p] = [cur[3], cur[7], cur[11], cur[15]];
    st.top_luma[p][mb_x * 4..mb_x * 4 + 4].copy_from_slice(&cur[12..16]);
}

/// The residual and its `nC` bookkeeping, shared by the intra and inter
/// macroblock writers: the syntax from `coded_block_pattern` onwards is
/// the same for both — only whether an Intra_16x16 DC block leads (and
/// shortens the AC spans) differs, and `luma_dc` carries exactly that.
///
/// Mirrors `parse_residual_luma_like` for plane 0 and then the chroma of
/// `parse_residual_cavlc`. `cur` / `curc` are the within-macroblock
/// counts decoded so far, which is what the reader's `nC` reads for a
/// block whose left or top neighbour is in this same macroblock.
#[allow(clippy::too_many_arguments)]
fn write_mb_residual(
    w: &mut BitWriter,
    st: &mut NzState,
    mb_x: usize,
    left: bool,
    top: bool,
    luma_dc: Option<&[i16; 16]>,
    transform_8x8: bool,
    cbp: usize,
    luma: &[[i16; 16]; 16],
    chroma_dc: &[[i16; 16]; 2],
    chroma_ac: &[[[i16; 16]; 16]; 2],
    nz_luma: &[u8; 16],
    nz_chroma: &[[u8; 16]; 2],
) {
    let chroma = st.rows != 0;
    let mut curc = [[0u8; 8]; 2];

    // Luma, then (4:4:4) Cb and Cr coded the same way — the mirror of
    // `parse_residual_cavlc`'s plane order, each plane's `nC` from its own
    // neighbour counts (`plane_nc` in src/h264/cavlc.rs).
    write_plane_residual(
        w,
        st,
        0,
        mb_x,
        left,
        top,
        luma_dc,
        transform_8x8,
        cbp,
        luma,
        nz_luma,
    );
    if st.c444 {
        // 4:4:4's chroma planes are luma-style, transform size included.
        write_plane_residual(
            w,
            st,
            1,
            mb_x,
            left,
            top,
            luma_dc.is_some().then_some(&chroma_dc[0]),
            transform_8x8,
            cbp,
            &chroma_ac[0],
            &nz_chroma[0],
        );
        write_plane_residual(
            w,
            st,
            2,
            mb_x,
            left,
            top,
            luma_dc.is_some().then_some(&chroma_dc[1]),
            transform_8x8,
            cbp,
            &chroma_ac[1],
            &nz_chroma[1],
        );
    }
    if chroma && cbp & 0x30 != 0 {
        for comp in 0..2 {
            let dc = widen_dc(&chroma_dc[comp]);
            if st.rows == 4 {
                let _ = write_residual_block_cavlc(w, -2, &dc, &SCAN_CHROMA_DC_422, 0, 7, 8);
            } else {
                let _ = write_residual_block_cavlc(w, -1, &dc, &SCAN_CHROMA_DC, 0, 3, 4);
            }
        }
        if cbp & 0x20 != 0 {
            for comp in 0..2 {
                for blk in 0..2 * st.rows {
                    let (bx, by) = (blk & 1, blk >> 1);
                    let a = if bx > 0 {
                        Some(curc[comp][by * 2 + bx - 1])
                    } else if left {
                        Some(st.left_chroma[comp][by])
                    } else {
                        None
                    };
                    let b = if by > 0 {
                        Some(curc[comp][(by - 1) * 2 + bx])
                    } else if top {
                        Some(st.top_chroma[comp][mb_x * 2 + bx])
                    } else {
                        None
                    };
                    let lv = widen(&chroma_ac[comp][blk]);
                    let scan4 = if st.field { &FIELD_SCAN4X4 } else { &ZIGZAG4X4 };
                    let n = write_residual_block_cavlc(w, nc_of(a, b), &lv, scan4, 1, 15, 15);
                    debug_assert_eq!(
                        n, nz_chroma[comp][blk] as usize,
                        "chroma block {comp}/{blk}: the decision's count disagrees with the writer's"
                    );
                    curc[comp][blk] = n as u8;
                }
            }
        }
    }

    // What the neighbours will read of the 4:2:x chroma state (the
    // luma-like planes updated theirs above).
    for comp in 0..2 {
        for r in 0..st.rows {
            st.left_chroma[comp][r] = curc[comp][r * 2 + 1];
        }
        if st.rows != 0 {
            let base = (st.rows - 1) * 2;
            st.top_chroma[comp][mb_x * 2] = curc[comp][base];
            st.top_chroma[comp][mb_x * 2 + 1] = curc[comp][base + 1];
        }
    }
}

/// Write every macroblock of an all-intra CAVLC picture: the shared walk
/// (`h264_pic::code_intra_picture`) makes the decisions, reconstructs and runs the
/// loop filter; this side only spells bits and keeps the `nC` state. The
/// slice header is already written; the caller closes the RBSP.
///
/// `qp` is the slice QP, which every macroblock is coded at —
/// [`MbDecision::qp_delta`] passes through as `mb_qp_delta` and is zero
/// until something adapts the quantiser. Refuses nothing at run time: the
/// caller keeps 4:4:4 and lossless on the PCM path, and a `debug_assert`
/// holds the door.
pub fn write_intra_picture<S: Sample>(
    w: &mut BitWriter,
    g: &Geometry,
    tools: &IntraTools<S>,
    qp: u8,
    planes: &[Plane<'_, S>],
    rec: &mut [Recon<S>],
) -> PicMotion {
    let mbs_wide = g.mbs_wide as usize;
    let rows = if g.chroma == crate::picture::ChromaFormat::Yuv444 {
        0
    } else {
        g.chroma_mb().1 as usize / 4
    };
    let mut st = NzState::new(
        mbs_wide,
        rows,
        g.chroma == crate::picture::ChromaFormat::Yuv444,
    );
    st.field = g.field_pic;
    let t8x8 = tools.transform_8x8;
    code_intra_picture(g, tools, qp, planes, rec, |mb_x, mb_y, dec| {
        write_macroblock(w, dec, &mut st, mb_x, mb_x > 0, mb_y > 0, 0, t8x8);
    })
}

/// Write every macroblock of a P CAVLC picture: the shared walk
/// (`h264_pic::code_p_picture`) owns the motion search, the skip decision, the
/// intra fallback and every neighbour state a decoder derives; this side
/// spells the bits — the `mb_skip_run` bookkeeping and the macroblock
/// layers — and keeps the `nC` state. The slice header is already
/// written; the caller closes the RBSP.
///
/// `refp` is the reference picture's reconstruction, borders already
/// replicated ([`crate::encode::h264_me::prepare_reference`]); exactly one
/// reference is active, which is why no `ref_idx` is ever written.
#[allow(clippy::too_many_arguments)]
pub fn write_p_picture<S: Sample>(
    w: &mut BitWriter,
    g: &Geometry,
    tools: &IntraTools<S>,
    qp: u8,
    planes: &[Plane<'_, S>],
    rec: &mut [Recon<S>],
    refp: &[Recon<S>],
    weights: Option<&crate::h264::slice::PredWeightTable>,
) -> PicMotion {
    let mbs_wide = g.mbs_wide as usize;
    let rows = if g.chroma == crate::picture::ChromaFormat::Yuv444 {
        0
    } else {
        g.chroma_mb().1 as usize / 4
    };
    let mut st = NzState::new(
        mbs_wide,
        rows,
        g.chroma == crate::picture::ChromaFormat::Yuv444,
    );
    st.field = g.field_pic;
    // `mb_skip_run`: counted here, written before each coded macroblock,
    // and flushed after the last one — the reader expects a run before
    // *every* coded macroblock (zero included) and a bare trailing run
    // when the slice ends in skips (7.3.4).
    let mut skip_run: u32 = 0;
    let t8x8 = tools.transform_8x8;
    let fmbs = code_p_picture(
        g,
        tools,
        qp,
        planes,
        rec,
        refp,
        weights,
        |mb_x, mb_y, mb| match mb {
            PMb::Skip(_) => {
                skip_run += 1;
                skip_nz(&mut st, mb_x);
            }
            PMb::Coded(dec) => {
                w.ue(skip_run);
                skip_run = 0;
                write_p16_macroblock(w, dec, &mut st, mb_x, mb_x > 0, mb_y > 0, t8x8, false);
            }
            PMb::Intra(idec) => {
                w.ue(skip_run);
                skip_run = 0;
                // Intra in a P slice: the same macroblock, `mb_type` shifted
                // by 5 (Table 7-11's note).
                write_macroblock(w, idec, &mut st, mb_x, mb_x > 0, mb_y > 0, 5, t8x8);
            }
        },
    );
    if skip_run > 0 {
        w.ue(skip_run);
    }
    fmbs
}

/// Write one coded B macroblock of any shape — `mb_type` (Table 7-14)
/// through the residual. The skip run belongs to the caller; no `ref_idx`
/// is written because exactly one reference is active per list, and the
/// mvds come **list-major**: every partition's `mvd_l0` in partition
/// order, then every partition's `mvd_l1` (7.3.5.1's and 7.3.5.2's
/// prediction loops, which the reader's `parse_mb_cavlc` walks the same
/// way). `B_Direct_16x16` carries no motion syntax at all — `mb_type` 0,
/// then straight to the coded block pattern — and neither does a
/// `B_Direct_8x8` sub-macroblock, whose `sub_mb_type` of 0 is all it
/// spells.
#[allow(clippy::too_many_arguments)]
fn write_b_macroblock(
    w: &mut BitWriter,
    dec: &BDecision,
    st: &mut NzState,
    mb_x: usize,
    left: bool,
    top: bool,
    t8x8_mode: bool,
    ref_idx_zeros: bool,
) {
    debug_assert!(
        !matches!(dec.kind, BMbKind::BSkip | BMbKind::UseIntra),
        "only a coded B macroblock carries this syntax"
    );
    debug_assert!(
        dec.ref_idx.iter().flatten().all(|&r| r <= 0),
        "multi-reference lists need te(v) ref_idx"
    );
    w.ue(dec.mb_type());
    if dec.kind == BMbKind::B8x8 {
        // `sub_mb_pred()`: the four `sub_mb_type`s first, all of them
        // before any motion.
        for part in 0..4 {
            w.ue(dec.sub_mb_type(part));
        }
    }
    // An MBAFF field macroblock's reference indices, all 0 (see
    // `write_p16_macroblock`): per list, per partition that uses the list
    // and is not direct, before any mvd.
    if ref_idx_zeros && dec.kind != BMbKind::BDirect16 {
        for list in 0..2 {
            if dec.kind == BMbKind::B8x8 {
                for part in 0..4 {
                    if !dec.is_direct_part(part) && dec.used(part)[list] {
                        w.te(0, 1);
                    }
                }
            } else {
                for &(x, y, _, _) in crate::h264::cavlc::mb_partitions(dec.kind.dec_kind()) {
                    if dec.used(part_index_of(x, y))[list] {
                        w.te(0, 1);
                    }
                }
            }
        }
    }
    if dec.kind != BMbKind::BDirect16 {
        // `ref_idx_lX` is absent throughout (one active reference per
        // list). Then the mvds, list-major, one per explicit rectangle in
        // syntax order, x then y.
        let mut rects = [(0usize, 0usize, 0usize, 0usize); 16];
        let n = dec.rects(&mut rects);
        for list in 0..2 {
            for &(x, y, _, _) in rects.iter().take(n) {
                let part = part_index_of(x, y);
                if dec.is_direct_part(part) || !dec.used(part)[list] {
                    continue;
                }
                let mvd = dec.mvd[list][(y / 4) * 4 + x / 4];
                w.se(mvd.x as i32);
                w.se(mvd.y as i32);
            }
        }
    }
    let cbp = (dec.cbp_luma | (dec.cbp_chroma << 4)) as usize;
    let code = if st.rows != 0 {
        INTER_CBP_TO_GOLOMB[cbp]
    } else {
        INTER_CBP_TO_GOLOMB_GRAY[cbp]
    };
    w.ue(code as u32);
    // The flag comes after the coded block pattern, only when some luma
    // block is coded, and only when every sub-macroblock partition is at
    // least 8x8. `B_Direct_16x16` and a direct sub-macroblock count as
    // 8x8, because the SPS this encoder writes sets
    // `direct_8x8_inference_flag`.
    if t8x8_mode && dec.cbp_luma != 0 && dec.no_sub_mb_part_less_than_8x8() {
        w.flag(dec.transform_8x8);
    }
    debug_assert!(
        !dec.transform_8x8
            || (t8x8_mode && dec.cbp_luma != 0 && dec.no_sub_mb_part_less_than_8x8())
    );
    if cbp != 0 {
        w.se(dec.qp_delta as i32);
    }
    write_mb_residual(
        w,
        st,
        mb_x,
        left,
        top,
        None,
        dec.transform_8x8,
        cbp,
        &dec.luma,
        &dec.chroma_dc,
        &dec.chroma_ac,
        &dec.nz_luma,
        &dec.nz_chroma,
    );
}

/// Write every macroblock of a B CAVLC picture: the shared walk
/// (`h264_pic::code_b_picture`) owns the searches, the direct derivation and the
/// intra fallback; this side spells the bits — the same `mb_skip_run`
/// bookkeeping as P — and keeps the `nC` state. Returns the picture's
/// motion record for the caller's reference bookkeeping.
#[allow(clippy::too_many_arguments)]
pub fn write_b_picture<S: Sample>(
    w: &mut BitWriter,
    g: &Geometry,
    tools: &IntraTools<S>,
    qp: u8,
    planes: &[Plane<'_, S>],
    rec: &mut [Recon<S>],
    refs: [&[Recon<S>]; 2],
    col: &Colocated,
    weights: crate::encode::h264_me::BWeights<'_>,
) -> PicMotion {
    let mbs_wide = g.mbs_wide as usize;
    let rows = if g.chroma == crate::picture::ChromaFormat::Yuv444 {
        0
    } else {
        g.chroma_mb().1 as usize / 4
    };
    let mut st = NzState::new(
        mbs_wide,
        rows,
        g.chroma == crate::picture::ChromaFormat::Yuv444,
    );
    st.field = g.field_pic;
    let mut skip_run: u32 = 0;
    let t8x8 = tools.transform_8x8;
    let fmbs = code_b_picture(
        g,
        tools,
        qp,
        planes,
        rec,
        refs,
        col,
        weights,
        |mb_x, mb_y, mb| match mb {
            BMb::Skip(_) => {
                skip_run += 1;
                skip_nz(&mut st, mb_x);
            }
            BMb::Direct(dec) | BMb::Explicit(dec) => {
                w.ue(skip_run);
                skip_run = 0;
                write_b_macroblock(w, dec, &mut st, mb_x, mb_x > 0, mb_y > 0, t8x8, false);
            }
            BMb::Intra(idec) => {
                w.ue(skip_run);
                skip_run = 0;
                // Intra in a B slice: the same macroblock, `mb_type` shifted
                // by 23 (Table 7-14's note).
                write_macroblock(w, idec, &mut st, mb_x, mb_x > 0, mb_y > 0, 23, t8x8);
            }
        },
    );
    if skip_run > 0 {
        w.ue(skip_run);
    }
    fmbs
}

/// The nonzero counts one written macroblock leaves for the `nC` of the
/// macroblocks after it — what the reader stores: each 4x4 block's
/// `TotalCoeff` (the four sub-scans' under the 8x8 transform, the AC
/// blocks' for Intra_16x16), zero for every block of an uncoded 8x8, for
/// chroma AC below a chroma pattern of 2, and for a skipped macroblock.
#[derive(Clone, Copy)]
struct MbCounts {
    luma: [u8; 16],
    chroma: [[u8; 16]; 2],
}

impl MbCounts {
    const SKIP: MbCounts = MbCounts {
        luma: [0; 16],
        chroma: [[0; 16]; 2],
    };

    fn of(cbp_luma: u8, cbp_chroma: u8, nz_luma: &[u8; 16], nz_chroma: &[[u8; 16]; 2]) -> Self {
        let mut luma = [0u8; 16];
        for (r, v) in luma.iter_mut().enumerate() {
            if cbp_luma & (1 << ((r / 8) * 2 + (r % 4) / 2)) != 0 {
                *v = nz_luma[r];
            }
        }
        MbCounts {
            luma,
            chroma: if cbp_chroma == 2 {
                *nz_chroma
            } else {
                [[0; 16]; 2]
            },
        }
    }

    fn of_mb(mb: &PairMb) -> Self {
        match mb {
            PairMb::Intra(d) | PairMb::PIntra(d) | PairMb::BIntra(d) => {
                Self::of(d.cbp_luma, d.cbp_chroma, &d.nz_luma, &d.nz_chroma)
            }
            PairMb::P(d) => Self::of(d.cbp_luma, d.cbp_chroma, &d.nz_luma, &d.nz_chroma),
            PairMb::B(d) => Self::of(d.cbp_luma, d.cbp_chroma, &d.nz_luma, &d.nz_chroma),
        }
    }
}

/// Write one MBAFF pair in CAVLC: the decoder's CAVLC MBAFF slice loop
/// (src/h264/decoder.rs) mirrored. A skipped macroblock extends
/// `mb_skip_run`; a coded one is preceded by the run, then — for a top
/// macroblock, or a bottom one whose top was skipped — the pair's
/// `mb_field_decoding_flag`, then its layer, with every `nC` read from the
/// blocks the decoder's MBAFF neighbour derivation names and, for a field
/// macroblock, the field scans and its reference indices. Returns the two
/// macroblocks' counts.
#[allow(clippy::too_many_arguments)]
fn write_pair_cavlc(
    w: &mut BitWriter,
    skip_run: &mut u32,
    base: &[Option<MbCounts>],
    pair: &CodedPair,
    pm: &PicMotion,
    inter: bool,
    rows: usize,
    t8x8: bool,
) -> [MbCounts; 2] {
    let mbw = pm.info.mb_width;
    let (top, bot) = (pair.top, pair.top + mbw);
    let mut local: [Option<MbCounts>; 2] = [None, None];
    for b in 0..2 {
        let addr = top + b * mbw;
        let mb = &pair.mbs[b];
        if mb.is_skip() {
            *skip_run += 1;
            local[b] = Some(MbCounts::SKIP);
            continue;
        }
        if inter {
            w.ue(*skip_run);
            *skip_run = 0;
        }
        if b == 0 || pair.mbs[0].is_skip() {
            w.flag(pair.field); // mb_field_decoding_flag
        }
        let mut nb = MbNeighbours::default();
        nb.derive_mbaff_into(&pm.info, addr, 0, pair.field);
        let mut st = NzState::new(1, rows, false);
        st.field = pair.field;
        {
            let get = |a: usize| -> MbCounts {
                (if a == top {
                    local[0]
                } else if a == bot {
                    local[1]
                } else {
                    base[a]
                })
                .expect("an MBAFF neighbour is written before it is read")
            };
            for k in 0..4 {
                if let Some((a, blk)) = nb.block(-1, k as i32) {
                    st.left_luma[0][k] = get(a).luma[blk];
                }
                if let Some((a, blk)) = nb.block(k as i32, -1) {
                    st.top_luma[0][k] = get(a).luma[blk];
                }
            }
            for r in 0..rows {
                if let Some((a, cblk)) = nb.block_c(-1, r as i32, rows as i32) {
                    for comp in 0..2 {
                        st.left_chroma[comp][r] = get(a).chroma[comp][cblk];
                    }
                }
            }
            if rows > 0 {
                for c in 0..2 {
                    if let Some((a, cblk)) = nb.block_c(c as i32, -1, rows as i32) {
                        for comp in 0..2 {
                            st.top_chroma[comp][c] = get(a).chroma[comp][cblk];
                        }
                    }
                }
            }
        }
        let (left, above) = (nb.a.is_some(), nb.b.is_some());
        match mb {
            PairMb::Intra(d) => write_macroblock(w, d, &mut st, 0, left, above, 0, t8x8),
            PairMb::PIntra(d) => write_macroblock(w, d, &mut st, 0, left, above, 5, t8x8),
            PairMb::BIntra(d) => write_macroblock(w, d, &mut st, 0, left, above, 23, t8x8),
            PairMb::P(d) => write_p16_macroblock(w, d, &mut st, 0, left, above, t8x8, pair.field),
            PairMb::B(d) => write_b_macroblock(w, d, &mut st, 0, left, above, t8x8, pair.field),
        }
        local[b] = Some(MbCounts::of_mb(mb));
    }
    [local[0].expect("written"), local[1].expect("written")]
}

/// The CAVLC slice data of an MBAFF picture, written pair by pair as the
/// walk decides each, every macroblock's counts kept by storage address.
/// [`MbaffCavlc::finish`] writes a trailing skip run; the caller closes the
/// RBSP.
pub(crate) struct MbaffCavlc<'w> {
    w: &'w mut BitWriter,
    counts: Vec<Option<MbCounts>>,
    skip_run: u32,
    inter: bool,
    rows: usize,
    t8x8: bool,
}

impl<'w> MbaffCavlc<'w> {
    /// Begin the slice data of an MBAFF picture of `slice` type.
    pub(crate) fn new<S: Sample>(
        w: &'w mut BitWriter,
        g: &Geometry,
        tools: &IntraTools<S>,
        slice: crate::h264::SliceType,
    ) -> Self {
        let rows = match g.chroma {
            crate::picture::ChromaFormat::Yuv420 => 2,
            crate::picture::ChromaFormat::Yuv422 => 4,
            _ => 0,
        };
        MbaffCavlc {
            w,
            counts: vec![None; (g.mbs_wide * g.mbs_high) as usize],
            skip_run: 0,
            inter: !slice.is_intra(),
            rows,
            t8x8: tools.transform_8x8,
        }
    }

    /// The run of skips the slice ends in, if it ends in skips.
    pub(crate) fn finish(self) {
        if self.skip_run > 0 {
            self.w.ue(self.skip_run);
        }
    }
}

impl PairWriter for MbaffCavlc<'_> {
    fn trial_bits(&self, pair: &CodedPair, pm: &PicMotion) -> u64 {
        let mut w = BitWriter::new();
        let mut run = self.skip_run;
        let _ = write_pair_cavlc(
            &mut w,
            &mut run,
            &self.counts,
            pair,
            pm,
            self.inter,
            self.rows,
            self.t8x8,
        );
        w.position()
    }

    fn write_pair(&mut self, pair: &CodedPair, pm: &PicMotion) {
        let c = write_pair_cavlc(
            self.w,
            &mut self.skip_run,
            &self.counts,
            pair,
            pm,
            self.inter,
            self.rows,
            self.t8x8,
        );
        let mbw = pm.info.mb_width;
        self.counts[pair.top] = Some(c[0]);
        self.counts[pair.top + mbw] = Some(c[1]);
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use crate::bitreader::BitReader;
    use crate::encode::h264_intra::{IntraCtx, MbAvail, PredMode, code_macroblock, quad_rasters};
    use crate::encode::h264_me::test_b_decision as b_decision;
    use crate::encode::h264_syntax::recon_plane;
    use crate::h264::SliceType;
    use crate::h264::cavlc::{intra_mb_type, parse_mb_cavlc};
    use crate::h264::frame::{CHROMA_PAD, LUMA_PAD};
    use crate::h264::mb::chroma_qp;
    use crate::h264::mb::{MbKind as DecKind, MbLayer, MbNeighbours, PicInfo, SliceCtx};
    use crate::h264::recon::QpState;
    use crate::h264::sps::ScalingLists;
    use crate::h264::tables::ZIGZAG8X8;
    use crate::h264::transform::Dequant;

    fn flat() -> ScalingLists {
        ScalingLists {
            list4x4: [[16; 16]; 6],
            list8x8: [[16; 64]; 6],
        }
    }

    /// The derived coded_block_pattern mappings really invert the reader's:
    /// codeNum -> cbp -> codeNum is the identity over every entry.
    #[test]
    fn cbp_mapping_round_trips() {
        for code in 0..48usize {
            assert_eq!(
                INTRA_CBP_TO_GOLOMB[GOLOMB_TO_INTRA4X4_CBP[code] as usize] as usize, code,
                "intra cbp codeNum {code}"
            );
        }
        for code in 0..16usize {
            assert_eq!(
                INTRA_CBP_TO_GOLOMB_GRAY[GOLOMB_TO_INTRA4X4_CBP_GRAY[code] as usize] as usize, code,
                "monochrome intra cbp codeNum {code}"
            );
        }
        for code in 0..48usize {
            assert_eq!(
                INTER_CBP_TO_GOLOMB[GOLOMB_TO_INTER_CBP[code] as usize] as usize, code,
                "inter cbp codeNum {code}"
            );
        }
        for code in 0..16usize {
            assert_eq!(
                INTER_CBP_TO_GOLOMB_GRAY[GOLOMB_TO_INTER_CBP_GRAY[code] as usize] as usize, code,
                "monochrome inter cbp codeNum {code}"
            );
        }
    }

    /// A `SliceCtx` for parsing one macroblock of a single-reference P
    /// slice, which is the only kind this encoder writes.
    fn p_ctx() -> SliceCtx {
        SliceCtx {
            slice_type: SliceType::P,
            slice_num: 0,
            num_ref_idx: [1, 0],
            direct_spatial: false,
            transform_8x8_mode: false,
            constrained_intra_pred: false,
            direct_8x8_inference: true,
            chroma_format_idc: 1,
            cabac: false,
            bit_depth: 8,
            transform_bypass: false,
            scaling_plane: 0,
            x264_old_444: false,
            field_pic: false,
            mbaff: false,
            sp: false,
            sp_switch: false,
            sp_qs: 0,
            sp_qsc: [0; 2],
        }
    }

    /// Write one P_L0_16x16 macroblock and hand the bits to the production
    /// reader: kind, the absent ref_idx, the mvd, cbp, the nonzero counts
    /// (the `nC` state a next macroblock would read) and the QP
    /// bookkeeping must all come back as written. Covers an empty
    /// macroblock (cbp 0, so no `mb_qp_delta` on the wire), a dense one,
    /// and negative mvd components — the sign bit of se(v) is exactly the
    /// kind of thing only a round trip through the real reader catches.
    #[test]
    fn a_p16_macroblock_round_trips_through_the_reader() {
        for (mvdx, mvdy, coded) in [
            (0i16, 0i16, false),
            (7, -3, true),
            (-13, 21, true),
            (1, 0, false),
        ] {
            let mut dec = InterDecision {
                mvd: [crate::h264::frame::Mv::new(mvdx, mvdy); 16],
                ..InterDecision::default()
            };
            if coded {
                dec.luma[0][0] = 5;
                dec.luma[0][7] = -2;
                dec.nz_luma[0] = 2;
                dec.luma[8][3] = 1;
                dec.nz_luma[8] = 1;
                dec.cbp_luma = 0b0101; // 8x8 blocks 0 (raster 0) and 2 (raster 8)
                dec.chroma_dc[1][0] = -3;
                dec.chroma_ac[0][1][2] = 2;
                dec.nz_chroma[0][1] = 1;
                dec.cbp_chroma = 2;
            }

            let mut st = NzState::new(1, 2, false);
            let mut w = BitWriter::new();
            write_p16_macroblock(&mut w, &dec, &mut st, 0, false, false, false, false);
            w.rbsp_trailing_bits();
            let rbsp = w.into_rbsp();

            let ctx = p_ctx();
            let info = PicInfo::new(1, 1);
            let nb = MbNeighbours {
                mb_width: 1,
                ..MbNeighbours::default()
            };
            let dq = Dequant::new(&flat());
            let mut qps = QpState {
                prev_qp: 28,
                chroma_offset: [0, 0],
            };
            let mut r = BitReader::new(&rbsp);
            let t = r.ue();
            let mut layer = MbLayer::new(DecKind::I4x4);
            parse_mb_cavlc(&mut r, &ctx, &info, &nb, t, &mut layer, &dq, &mut qps)
                .expect("the reader rejected what the writer produced");
            assert!(!r.overrun());

            assert_eq!(layer.kind, DecKind::Inter16x16, "mvd ({mvdx},{mvdy})");
            assert_eq!(
                layer.ref_idx[0][0], 0,
                "one active reference infers ref_idx 0"
            );
            assert_eq!(layer.mvd[0].mvd[0], crate::h264::frame::Mv::new(mvdx, mvdy));
            assert_eq!(layer.cbp, dec.cbp_luma | (dec.cbp_chroma << 4));
            assert_eq!(layer.qp_delta, if coded { dec.qp_delta as i32 } else { 0 });
            assert_eq!(
                layer.qp, 28,
                "constant QP whether or not a delta was carried"
            );
            for blk in 0..16 {
                assert_eq!(layer.nz[0][blk], dec.nz_luma[blk], "luma nz {blk}");
            }
            for comp in 0..2 {
                for blk in 0..4 {
                    assert_eq!(
                        layer.chroma_nz[comp][blk], dec.nz_chroma[comp][blk],
                        "chroma nz {comp}/{blk}"
                    );
                }
            }
        }
    }

    /// Write one B macroblock of every shape and hand the bits to the
    /// production reader: the kind, each partition's direction, the
    /// sub-macroblock types, the mvds list-major, the absent ref_idx, the
    /// INTER coded-block-pattern column and the nonzero counts must all
    /// come back as written — and `B_Direct_16x16` must come back as
    /// exactly `mb_type` 0 with no motion syntax consumed, a
    /// `B_Direct_8x8` as a sub-macroblock with none.
    ///
    /// Every direction pair of Table 7-14's two-partition rows is
    /// written, and `B_8x8` trees mixing direct with every shape and
    /// direction, because the mvd order (every partition's list 0, then
    /// every partition's list 1, skipping the direct ones and the unused
    /// lists) is exactly the kind of thing a single case cannot pin.
    #[test]
    fn every_b_shape_round_trips_through_the_reader() {
        use crate::h264::frame::Mv;
        use crate::h264::mb::{PRED_BI, PRED_L0, PRED_L1};
        let mut cases: Vec<BDecision> = Vec::new();
        cases.push(b_decision(
            BMbKind::BDirect16,
            [PRED_BI; 4],
            [SubMbShape::S8x8; 4],
            1,
        ));
        for dir in [PRED_L0, PRED_L1, PRED_BI] {
            cases.push(b_decision(BMbKind::B16, [dir; 4], [SubMbShape::S8x8; 4], 2));
        }
        for d0 in [PRED_L0, PRED_L1, PRED_BI] {
            for d1 in [PRED_L0, PRED_L1, PRED_BI] {
                cases.push(b_decision(
                    BMbKind::B16x8,
                    [d0, d0, d1, d1],
                    [SubMbShape::S8x8; 4],
                    3,
                ));
                cases.push(b_decision(
                    BMbKind::B8x16,
                    [d0, d1, d0, d1],
                    [SubMbShape::S8x8; 4],
                    4,
                ));
            }
        }
        cases.push(b_decision(
            BMbKind::B8x8,
            [PRED_BI, PRED_L0, PRED_L1, PRED_BI],
            [
                SubMbShape::Direct,
                SubMbShape::S8x8,
                SubMbShape::S8x4,
                SubMbShape::S4x4,
            ],
            5,
        ));
        cases.push(b_decision(
            BMbKind::B8x8,
            [PRED_BI, PRED_L0, PRED_L0, PRED_L1],
            [
                SubMbShape::S4x8,
                SubMbShape::Direct,
                SubMbShape::Direct,
                SubMbShape::S8x8,
            ],
            6,
        ));
        cases.push(b_decision(
            BMbKind::B8x8,
            [PRED_L0, PRED_L0, PRED_L1, PRED_BI],
            [
                SubMbShape::S8x4,
                SubMbShape::S4x8,
                SubMbShape::S4x4,
                SubMbShape::S8x8,
            ],
            7,
        ));
        cases.push(b_decision(
            BMbKind::B8x8,
            [PRED_L0; 4],
            [SubMbShape::Direct; 4],
            8,
        ));

        for dec in &cases {
            let mut st = NzState::new(1, 2, false);
            let mut w = BitWriter::new();
            write_b_macroblock(&mut w, dec, &mut st, 0, false, false, false, false);
            w.rbsp_trailing_bits();
            let rbsp = w.into_rbsp();

            let ctx = SliceCtx {
                slice_type: SliceType::B,
                num_ref_idx: [1, 1],
                direct_spatial: true,
                ..p_ctx()
            };
            let info = PicInfo::new(1, 1);
            let nb = MbNeighbours {
                mb_width: 1,
                ..MbNeighbours::default()
            };
            let dq = Dequant::new(&flat());
            let mut qps = QpState {
                prev_qp: 28,
                chroma_offset: [0, 0],
            };
            let mut r = BitReader::new(&rbsp);
            let t = r.ue();
            let mut layer = MbLayer::new(DecKind::I4x4);
            parse_mb_cavlc(&mut r, &ctx, &info, &nb, t, &mut layer, &dq, &mut qps)
                .expect("the reader rejected what the writer produced");
            assert!(!r.overrun());
            let tag = format!("{:?} dir {:?} sub {:?}", dec.kind, dec.dir, dec.sub_shape);

            assert_eq!(t, dec.mb_type(), "{tag}: mb_type");
            assert_eq!(layer.kind, dec.kind.dec_kind(), "{tag}: kind");
            for part in 0..4 {
                if dec.is_direct_part(part) {
                    if dec.kind == BMbKind::B8x8 {
                        assert_eq!(
                            layer.sub_shape[part],
                            SubMbShape::Direct,
                            "{tag}: part {part}"
                        );
                    }
                    continue;
                }
                assert_eq!(
                    layer.pred_dir[part], dec.dir[part],
                    "{tag}: part {part} direction"
                );
                if dec.kind == BMbKind::B8x8 {
                    assert_eq!(
                        layer.sub_shape[part], dec.sub_shape[part],
                        "{tag}: part {part} shape"
                    );
                }
                for l in 0..2 {
                    if dec.used(part)[l] {
                        assert_eq!(layer.ref_idx[l][part], 0, "{tag}: part {part} list {l}");
                    }
                }
            }
            // The reader keeps each mvd on its partition's top-left 4x4;
            // the decision replicates it over the rectangle, so the
            // top-left of every explicit rectangle is where they meet.
            let mut rects = [(0usize, 0usize, 0usize, 0usize); 16];
            let n = dec.rects(&mut rects);
            for &(x, y, _, _) in rects.iter().take(n) {
                let part = part_index_of(x, y);
                let blk = (y / 4) * 4 + x / 4;
                for l in 0..2 {
                    let want = if !dec.is_direct_part(part) && dec.used(part)[l] {
                        dec.mvd[l][blk]
                    } else {
                        Mv::ZERO
                    };
                    assert_eq!(
                        layer.mvd[blk].mvd[l], want,
                        "{tag}: block {blk} list {l} mvd"
                    );
                }
            }
            assert_eq!(
                layer.cbp,
                dec.cbp_luma | (dec.cbp_chroma << 4),
                "{tag}: cbp"
            );
            for blk in 0..16 {
                assert_eq!(layer.nz[0][blk], dec.nz_luma[blk], "{tag}: luma nz {blk}");
            }
        }
    }

    /// The encoder's `mb_type` and `sub_mb_type` numbering inverts the
    /// reader's tables exactly: every direction pair of both two-partition
    /// shapes unmaps to its own kind and directions through `b_mb_type`,
    /// and every (shape, direction) of a sub-macroblock through
    /// `b_sub_mb_type` — with the thirteen codes of Table 7-18 all
    /// produced, so no row is a number nothing spells.
    #[test]
    fn b_mb_type_numbering_inverts_the_readers_tables() {
        use crate::encode::h264_me::b_sub_mb_type_code;
        use crate::h264::cavlc::{b_mb_type, b_sub_mb_type};
        use crate::h264::mb::{PRED_BI, PRED_L0, PRED_L1};
        let dirs = [PRED_L0, PRED_L1, PRED_BI];
        let mut seen = std::collections::BTreeSet::new();
        for d0 in dirs {
            for d1 in dirs {
                for kind in [BMbKind::B16x8, BMbKind::B8x16] {
                    let dir = if kind == BMbKind::B16x8 {
                        [d0, d0, d1, d1]
                    } else {
                        [d0, d1, d0, d1]
                    };
                    let dec = BDecision {
                        kind,
                        dir,
                        ..BDecision::default()
                    };
                    let t = dec.mb_type();
                    assert!((4..=21).contains(&t), "{kind:?} {d0} {d1}: {t}");
                    assert!(
                        seen.insert(t),
                        "{kind:?} {d0} {d1}: mb_type {t} spelled twice"
                    );
                    let mut layer = MbLayer::new(DecKind::I4x4);
                    b_mb_type(t, &mut layer).unwrap();
                    assert_eq!(layer.kind, kind.dec_kind(), "{kind:?} {d0} {d1}");
                    assert_eq!(layer.pred_dir, dir, "{kind:?} {d0} {d1}");
                }
            }
            let dec = BDecision {
                kind: BMbKind::B16,
                dir: [d0; 4],
                ..BDecision::default()
            };
            let mut layer = MbLayer::new(DecKind::I4x4);
            b_mb_type(dec.mb_type(), &mut layer).unwrap();
            assert_eq!(layer.kind, DecKind::Inter16x16);
            assert_eq!(layer.pred_dir, [d0; 4]);
        }
        assert_eq!(seen.len(), 18, "the eighteen two-partition rows");
        let mut layer = MbLayer::new(DecKind::I4x4);
        b_mb_type(
            BDecision {
                kind: BMbKind::B8x8,
                ..BDecision::default()
            }
            .mb_type(),
            &mut layer,
        )
        .unwrap();
        assert_eq!(layer.kind, DecKind::Inter8x8);

        let mut codes = std::collections::BTreeSet::new();
        for shape in [
            SubMbShape::S8x8,
            SubMbShape::S8x4,
            SubMbShape::S4x8,
            SubMbShape::S4x4,
        ] {
            for dir in dirs {
                let t = b_sub_mb_type_code(shape, dir);
                assert!(
                    codes.insert(t),
                    "{shape:?} {dir}: sub_mb_type {t} spelled twice"
                );
                assert_eq!(b_sub_mb_type(t).unwrap(), (shape, dir), "{shape:?} {dir}");
            }
        }
        let t = b_sub_mb_type_code(SubMbShape::Direct, PRED_BI);
        assert_eq!(t, 0);
        assert_eq!(b_sub_mb_type(0).unwrap().0, SubMbShape::Direct);
        codes.insert(t);
        assert_eq!(
            codes.into_iter().collect::<Vec<_>>(),
            (0..=12).collect::<Vec<_>>()
        );
    }

    /// A 4:4:4 intra macroblock — decided by the real mode decision,
    /// its chroma planes replaying the luma modes luma-style — written
    /// and handed to the production reader with `chroma_format_idc` 3:
    /// the kind, the shared coded block pattern, and every plane's
    /// nonzero counts (the `nC` state a next macroblock's three planes
    /// would read) must come back as coded. No `intra_chroma_pred_mode`
    /// exists on the wire, which the reader enforces by construction.
    #[test]
    fn a_444_intra_macroblock_round_trips_through_the_reader() {
        use crate::h264::frame::LUMA_PAD;
        let tools = IntraTools::<u8>::new(false, false, 8);
        let mut seed = 77u32;
        let mut lcg = move || -> u8 {
            seed = seed.wrapping_mul(1664525).wrapping_add(1013904223);
            (seed >> 16) as u8
        };
        for qp in [14u8, 26, 40] {
            let qpc = chroma_qp(qp as i32, 0, 0);
            let ctx = IntraCtx {
                dsp: &tools.dsp,
                enc: &tools.enc,
                dist: &tools.dist,
                quant: &tools.quant,
                dequant: &tools.dequant,
                qp: qp as i32,
                qpc: [qpc; 2],
                qp_prime: qp as i32,
                qpc_prime: [qpc; 2],
                bit_depth: 8,
                max: 255,
                chroma_h: 16,
                c444: true,
                t8x8: false,
                subparts: false,
                field: false,
                chroma_mv_dy: [0; 2],
                motion: crate::encode::level::MotionLimits::NONE,
            };
            let mut rec = vec![
                recon_plane(16, 16, LUMA_PAD),
                recon_plane(16, 16, LUMA_PAD),
                recon_plane(16, 16, LUMA_PAD),
            ];
            let mut y = vec![0u8; 16 * 16];
            let mut cb = vec![0u8; 16 * 16];
            let mut cr = vec![0u8; 16 * 16];
            for i in 0..256 {
                y[i] = lcg();
                cb[i] = lcg();
                cr[i] = lcg();
            }
            let mb = MbAvail {
                left: false,
                top: false,
                top_left: false,
                top_right: false,
            };
            let (dec, _modes) = code_macroblock(
                &ctx,
                &mut rec,
                0,
                0,
                &y,
                16,
                [&cb, &cr],
                16,
                mb,
                &[None; 4],
                &[None; 4],
            );
            assert_eq!(dec.cbp_chroma, 0, "ChromaArrayType 3 has no chroma cbp");

            let mut st = NzState::new(1, 0, true);
            let mut w = BitWriter::new();
            write_macroblock(&mut w, &dec, &mut st, 0, false, false, 0, false);
            w.rbsp_trailing_bits();
            let rbsp = w.into_rbsp();

            let sctx = SliceCtx {
                chroma_format_idc: 3,
                ..p_ctx()
            };
            let sctx = SliceCtx {
                slice_type: SliceType::I,
                num_ref_idx: [0, 0],
                ..sctx
            };
            let info = PicInfo::new(1, 1);
            let nb = MbNeighbours {
                mb_width: 1,
                ..MbNeighbours::default()
            };
            let dq = Dequant::new(&flat());
            let mut qps = QpState {
                prev_qp: qp as i32,
                chroma_offset: [0, 0],
            };
            let mut r = BitReader::new(&rbsp);
            let t = r.ue();
            let mut layer = MbLayer::new(DecKind::I4x4);
            parse_mb_cavlc(&mut r, &sctx, &info, &nb, t, &mut layer, &dq, &mut qps)
                .expect("the reader rejected the 4:4:4 macroblock");
            assert!(!r.overrun());

            match dec.kind {
                MbKind::I4x4 => assert_eq!(layer.kind, DecKind::I4x4, "qp={qp}"),
                MbKind::I8x8 => assert_eq!(layer.kind, DecKind::I8x8, "qp={qp}"),
                MbKind::I16x16 => {
                    assert_eq!(layer.kind, DecKind::I16x16, "qp={qp}");
                    assert_eq!(layer.intra16_mode, dec.intra16_mode);
                    let want: Vec<i32> = dec.luma_dc.iter().map(|&v| v as i32).collect();
                    assert_eq!(&layer.dc[0][..], &want[..], "luma DC");
                    for comp in 0..2 {
                        let want: Vec<i32> =
                            dec.chroma_dc[comp].iter().map(|&v| v as i32).collect();
                        assert_eq!(&layer.dc[1 + comp][..], &want[..], "plane {comp} DC");
                    }
                }
            }
            assert_eq!(layer.cbp, dec.cbp_luma, "qp={qp} shared cbp");
            for blk in 0..16 {
                assert_eq!(layer.nz[0][blk], dec.nz_luma[blk], "qp={qp} luma nz {blk}");
                for comp in 0..2 {
                    assert_eq!(
                        layer.nz[1 + comp][blk],
                        dec.nz_chroma[comp][blk],
                        "qp={qp} plane {comp} nz {blk}"
                    );
                }
            }
        }
    }

    /// An intra macroblock in a P slice is the same macroblock with
    /// `mb_type` shifted by 5, and the production reader must unmap it to
    /// the same kind, mode and coded block pattern.
    #[test]
    fn an_intra_macroblock_in_a_p_slice_round_trips_with_its_offset() {
        let dec = MbDecision {
            intra16_mode: 1,
            chroma_mode: 2,
            ..MbDecision::default()
        };
        let mut st = NzState::new(1, 2, false);
        let mut w = BitWriter::new();
        w.ue(0); // the mb_skip_run a coded macroblock follows
        write_macroblock(&mut w, &dec, &mut st, 0, false, false, 5, false);
        w.rbsp_trailing_bits();
        let rbsp = w.into_rbsp();

        let ctx = p_ctx();
        let info = PicInfo::new(1, 1);
        let nb = MbNeighbours {
            mb_width: 1,
            ..MbNeighbours::default()
        };
        let dq = Dequant::new(&flat());
        let mut qps = QpState {
            prev_qp: 26,
            chroma_offset: [0, 0],
        };
        let mut r = BitReader::new(&rbsp);
        assert_eq!(r.ue(), 0, "the skip run before the coded macroblock");
        let t = r.ue();
        assert!(t >= 5, "an intra mb_type in a P slice starts at 5");
        let mut layer = MbLayer::new(DecKind::I4x4);
        parse_mb_cavlc(&mut r, &ctx, &info, &nb, t, &mut layer, &dq, &mut qps)
            .expect("the reader rejected the offset intra macroblock");
        assert_eq!(layer.kind, DecKind::I16x16);
        assert_eq!(layer.intra16_mode, 1);
        assert_eq!(layer.chroma_mode, 2);
        assert_eq!(layer.cbp, 0);
    }

    /// The I_16x16 `mb_type` arithmetic against the reader's unmapping,
    /// over every combination it can carry.
    #[test]
    fn mb_type_matches_the_readers_unmapping() {
        for mode in 0..4u8 {
            for chroma in 0..3u8 {
                for luma in [0u8, 15] {
                    let t = 1 + mode as u32 + 4 * chroma as u32 + 12 * (luma == 15) as u32;
                    let mut layer = MbLayer::new(DecKind::I4x4);
                    intra_mb_type(t, &mut layer).unwrap();
                    assert_eq!(layer.kind, DecKind::I16x16);
                    assert_eq!(layer.intra16_mode, mode, "t={t}");
                    assert_eq!(layer.cbp, luma | (chroma << 4), "t={t}");
                }
            }
        }
        let mut layer = MbLayer::new(DecKind::I16x16);
        intra_mb_type(0, &mut layer).unwrap();
        assert_eq!(layer.kind, DecKind::I4x4);
    }

    /// Write one macroblock and hand the bits to the production reader.
    /// The comparison covers everything the reader stores unscaled: the
    /// kind, modes, coded block pattern, QP bookkeeping, every nonzero
    /// count (which is the `nC` state the next macroblock would read),
    /// and the raw DC levels. The AC levels come back dequantised, and
    /// their coverage is the residual writer's own round-trip test.
    fn round_trip(dec: &MbDecision, chosen_modes: Option<&[u8; 16]>, qp: u8) {
        round_trip_fmt(dec, chosen_modes, qp, 1, false)
    }

    /// As [`round_trip`], with the chroma format and whether the PPS
    /// offers the 8x8 transform spelled out.
    fn round_trip_fmt(
        dec: &MbDecision,
        chosen_modes: Option<&[u8; 16]>,
        qp: u8,
        cfi: u32,
        t8x8: bool,
    ) {
        let c444 = cfi == 3;
        let rows = match cfi {
            1 => 2,
            2 => 4,
            _ => 0,
        };
        let mut st = NzState::new(1, rows, c444);
        let mut w = BitWriter::new();
        write_macroblock(&mut w, dec, &mut st, 0, false, false, 0, t8x8);
        w.rbsp_trailing_bits();
        let rbsp = w.into_rbsp();

        let ctx = SliceCtx {
            slice_type: SliceType::I,
            slice_num: 0,
            num_ref_idx: [0; 2],
            direct_spatial: false,
            transform_8x8_mode: t8x8,
            constrained_intra_pred: false,
            direct_8x8_inference: true,
            chroma_format_idc: cfi,
            cabac: false,
            bit_depth: 8,
            transform_bypass: false,
            scaling_plane: 0,
            x264_old_444: false,
            field_pic: false,
            mbaff: false,
            sp: false,
            sp_switch: false,
            sp_qs: 0,
            sp_qsc: [0; 2],
        };
        let info = PicInfo::new(1, 1);
        let nb = MbNeighbours {
            mb_width: 1,
            ..MbNeighbours::default()
        };
        let dq = Dequant::new(&flat());
        let mut qps = QpState {
            prev_qp: qp as i32,
            chroma_offset: [0, 0],
        };
        let mut r = BitReader::new(&rbsp);
        let t = r.ue();
        let mut layer = MbLayer::new(DecKind::I4x4);
        parse_mb_cavlc(&mut r, &ctx, &info, &nb, t, &mut layer, &dq, &mut qps)
            .expect("the reader rejected what the writer produced");
        assert!(!r.overrun());

        match dec.kind {
            MbKind::I4x4 => {
                assert_eq!(layer.kind, DecKind::I4x4);
                if let Some(modes) = chosen_modes {
                    assert_eq!(&layer.intra_modes, modes, "decoded 4x4 modes");
                }
            }
            MbKind::I8x8 => {
                assert_eq!(layer.kind, DecKind::I8x8);
                // The reader replicates each quad's mode over its four
                // 4x4s, which is the form the decision keeps too.
                if let Some(modes) = chosen_modes {
                    assert_eq!(&layer.intra_modes, modes, "decoded 8x8 modes");
                }
            }
            MbKind::I16x16 => {
                assert_eq!(layer.kind, DecKind::I16x16);
                assert_eq!(layer.intra16_mode, dec.intra16_mode);
                let dc: Vec<i32> = dec.luma_dc.iter().map(|&v| v as i32).collect();
                assert_eq!(&layer.dc[0][..], &dc[..], "luma DC levels");
            }
        }
        assert_eq!(
            layer.transform_8x8, dec.transform_8x8,
            "transform_size_8x8_flag"
        );
        assert_eq!(layer.cbp, dec.cbp_luma | (dec.cbp_chroma << 4), "cbp");
        assert_eq!(layer.chroma_mode, dec.chroma_mode);
        assert_eq!(layer.qp_delta, dec.qp_delta as i32);
        assert_eq!(layer.qp, qp as i32);
        // CAVLC stores exactly the counts the decision carries — its four
        // sub-scan counts under the 8x8 transform, one per 4x4 otherwise —
        // because those *are* the four blocks it codes.
        assert_eq!(layer.nz[0], dec.nz_luma, "luma nz");
        if c444 {
            for comp in 0..2 {
                assert_eq!(layer.nz[1 + comp], dec.nz_chroma[comp], "plane {comp} nz");
            }
        } else {
            for comp in 0..2 {
                for blk in 0..2 * rows {
                    assert_eq!(
                        layer.chroma_nz[comp][blk], dec.nz_chroma[comp][blk],
                        "chroma nz {comp}/{blk}"
                    );
                }
                if dec.cbp_chroma != 0 {
                    let n_dc = if rows == 4 { 8 } else { 4 };
                    let dc: Vec<i32> = dec.chroma_dc[comp][..n_dc]
                        .iter()
                        .map(|&v| v as i32)
                        .collect();
                    assert_eq!(&layer.chroma_dc[comp][..n_dc], &dc[..], "chroma DC {comp}");
                }
            }
        }
    }

    /// Decide a real macroblock from samples and round-trip it, over
    /// sources that reach the interesting shapes: flat (nothing coded),
    /// a gradient (I_16x16 plane prediction country) and noise (dense
    /// residual), across the QP range.
    #[test]
    fn coded_macroblocks_round_trip_through_the_reader() {
        let tools = IntraTools::<u8>::new(false, false, 8);
        let fill = |f: &mut dyn FnMut(usize, usize) -> u8| {
            let mut y = vec![0u8; 16 * 16];
            for r in 0..16 {
                for c in 0..16 {
                    y[r * 16 + c] = f(c, r);
                }
            }
            let mut cb = vec![0u8; 8 * 8];
            let mut cr = vec![0u8; 8 * 8];
            for r in 0..8 {
                for c in 0..8 {
                    cb[r * 8 + c] = f(c * 2, r * 2).wrapping_add(30);
                    cr[r * 8 + c] = f(c * 2 + 1, r * 2).wrapping_sub(30);
                }
            }
            (y, cb, cr)
        };
        let mut seed = 0x2718_2818u32;
        let mut lcg = move |x: usize, y: usize| -> u8 {
            seed = seed
                .wrapping_mul(1664525)
                .wrapping_add(1013904223 ^ ((x * 31 + y) as u32));
            (seed >> 16) as u8
        };
        let sources: [(&str, (Vec<u8>, Vec<u8>, Vec<u8>)); 3] = [
            ("flat", fill(&mut |_, _| 128)),
            ("gradient", fill(&mut |x, y| (60 + 6 * x + 3 * y) as u8)),
            ("noise", fill(&mut |x, y| lcg(x, y))),
        ];
        for (_name, (y, cb, cr)) in &sources {
            for qp in [10u8, 26, 40] {
                let qpc = chroma_qp(qp as i32, 0, 0);
                let ctx = IntraCtx {
                    dsp: &tools.dsp,
                    enc: &tools.enc,
                    dist: &tools.dist,
                    quant: &tools.quant,
                    dequant: &tools.dequant,
                    qp: qp as i32,
                    qpc: [qpc; 2],
                    qp_prime: qp as i32,
                    qpc_prime: [qpc; 2],
                    bit_depth: 8,
                    max: 255,
                    chroma_h: 8,
                    c444: false,
                    t8x8: false,
                    subparts: false,
                    field: false,
                    chroma_mv_dy: [0; 2],
                    motion: crate::encode::level::MotionLimits::NONE,
                };
                let mut rec = vec![
                    recon_plane(16, 16, LUMA_PAD),
                    recon_plane(8, 8, CHROMA_PAD),
                    recon_plane(8, 8, CHROMA_PAD),
                ];
                let mb = MbAvail {
                    left: false,
                    top: false,
                    top_left: false,
                    top_right: false,
                };
                let (dec, modes) = code_macroblock(
                    &ctx,
                    &mut rec,
                    0,
                    0,
                    y,
                    16,
                    [cb, cr],
                    8,
                    mb,
                    &[None; 4],
                    &[None; 4],
                );
                let chosen = (dec.kind == MbKind::I4x4).then_some(&modes);
                round_trip(&dec, chosen, qp);
            }
        }
    }

    /// Real `I_8x8` macroblocks, decided by the real mode decision with
    /// the 8x8 transform on offer, written and handed to the production
    /// CAVLC reader — over the chroma formats and the QP range, and over
    /// sources that reach the shapes the decision actually picks between.
    ///
    /// The two things this covers that no 4x4 test can: the four
    /// prediction-mode elements land where the reader takes them (before
    /// the coded block pattern, after a `transform_size_8x8_flag` that
    /// is itself read before `mb_pred()`), and the residual is four
    /// *interleaved* sub-scans of one 8x8 rather than four 4x4 blocks —
    /// so the `nC` bookkeeping is per sub-scan, and the levels come back
    /// in the 8x8's raster and not in four separate ones.
    #[test]
    fn coded_8x8_macroblocks_round_trip_through_the_reader() {
        let tools = IntraTools::<u8>::new(true, false, 8);
        let mut seed = 0x8080_8080u32;
        let mut lcg = move |x: usize, y: usize| -> u8 {
            seed = seed
                .wrapping_mul(1664525)
                .wrapping_add(1013904223 ^ ((x * 31 + y) as u32));
            (seed >> 16) as u8
        };
        // Smooth enough that the 8x8 candidate wins somewhere, detailed
        // enough that it does not always.
        let mut y = vec![0u8; 16 * 16];
        let mut cb = vec![0u8; 16 * 16];
        let mut cr = vec![0u8; 16 * 16];
        for r in 0..16 {
            for c in 0..16 {
                let smooth = (40 + 5 * c + 3 * r) as u8;
                y[r * 16 + c] = smooth.wrapping_add(lcg(c, r) / 8);
                cb[r * 16 + c] = smooth.wrapping_add(20);
                cr[r * 16 + c] = smooth.wrapping_sub(20);
            }
        }
        let mut saw_8x8 = false;
        for &(cfi, chroma_h, c444) in &[(1u32, 8usize, false), (2, 16, false), (3, 16, true)] {
            for qp in [10u8, 26, 33, 40] {
                let qpc = chroma_qp(qp as i32, 0, 0);
                let ctx = IntraCtx {
                    dsp: &tools.dsp,
                    enc: &tools.enc,
                    dist: &tools.dist,
                    quant: &tools.quant,
                    dequant: &tools.dequant,
                    qp: qp as i32,
                    qpc: [qpc; 2],
                    qp_prime: qp as i32,
                    qpc_prime: [qpc; 2],
                    bit_depth: 8,
                    max: 255,
                    chroma_h,
                    c444,
                    t8x8: true,
                    subparts: false,
                    field: false,
                    chroma_mv_dy: [0; 2],
                    motion: crate::encode::level::MotionLimits::NONE,
                };
                let cpad = if c444 { LUMA_PAD } else { CHROMA_PAD };
                let cw = if c444 { 16 } else { 8 };
                let mut rec = vec![
                    recon_plane(16, 16, LUMA_PAD),
                    recon_plane(cw, chroma_h as u32, cpad),
                    recon_plane(cw, chroma_h as u32, cpad),
                ];
                let mb = MbAvail {
                    left: false,
                    top: false,
                    top_left: false,
                    top_right: false,
                };
                let cstride = cw as usize;
                let (dec, modes) = code_macroblock(
                    &ctx,
                    &mut rec,
                    0,
                    0,
                    &y,
                    16,
                    [&cb, &cr],
                    cstride,
                    mb,
                    &[None; 4],
                    &[None; 4],
                );
                saw_8x8 |= dec.kind == MbKind::I8x8;
                let chosen = dec.kind.is_nxn().then_some(&modes);
                round_trip_fmt(&dec, chosen, qp, cfi, true);
            }
        }
        assert!(
            saw_8x8,
            "no configuration chose the 8x8 transform; the test proved nothing"
        );
    }

    /// A hand-built `I_8x8` decision, so the writer's 8x8 syntax is
    /// exercised whatever the mode decision above happens to choose —
    /// including an 8x8 whose coefficients land in only some of its four
    /// sub-scans, which is the case where a sub-scan count of zero has to
    /// travel intact through `nC` (and where a writer that summed them,
    /// as CABAC's neighbour record must, would desync the very next
    /// block's tables).
    #[test]
    fn a_synthetic_i8x8_macroblock_round_trips() {
        use crate::h264::cavlc::sub_block_counts_8x8_scan;
        let mut dec = MbDecision {
            kind: MbKind::I8x8,
            transform_8x8: true,
            luma_pred: [PredMode {
                use_predicted: true,
                rem: 0,
            }; 16],
            chroma_mode: 1,
            ..MbDecision::default()
        };
        // 8x8 blocks 0 and 3 coded. Block 0's coefficients sit only at
        // scan positions congruent to 0 and 2 mod 4, so sub-scans 1 and 3
        // count zero; block 3 is dense.
        let mut b0 = [0i16; 64];
        for i in 0..16 {
            b0[ZIGZAG8X8[4 * i] as usize] = if i % 3 == 0 { 3 } else { 0 };
            b0[ZIGZAG8X8[4 * i + 2] as usize] = if i % 5 == 0 { -2 } else { 0 };
        }
        let mut b3 = [0i16; 64];
        for (i, v) in b3.iter_mut().enumerate() {
            *v = ((i as i16 % 7) - 3) * if i % 2 == 0 { 1 } else { -1 };
        }
        dec.luma.as_flattened_mut()[0..64].copy_from_slice(&b0);
        dec.luma.as_flattened_mut()[192..256].copy_from_slice(&b3);
        for (blk8, b) in [(0usize, &b0), (3, &b3)] {
            let counts = sub_block_counts_8x8_scan(b, false);
            for (sub, &r) in quad_rasters(blk8).iter().enumerate() {
                dec.nz_luma[r] = counts[sub];
            }
        }
        assert!(
            quad_rasters(0).iter().any(|&r| dec.nz_luma[r] == 0),
            "the interesting case is an 8x8 with an empty sub-scan"
        );
        dec.cbp_luma = 0b1001;
        dec.chroma_dc[0][0] = 3;
        dec.chroma_dc[1][1] = 2;
        dec.chroma_ac[0][2][5] = -4;
        dec.nz_chroma[0][2] = 1;
        dec.cbp_chroma = 2;
        round_trip_fmt(&dec, Some(&[2u8; 16]), 28, 1, true);
    }

    /// The inter placement of the flag: after `coded_block_pattern`, and
    /// only when some luma block is coded. Both states of the flag, and a
    /// macroblock with no luma residual at all — where the element is
    /// absent from the wire and a decoder infers zero.
    #[test]
    fn a_p16_macroblock_with_the_8x8_transform_round_trips() {
        use crate::h264::cavlc::sub_block_counts_8x8_scan;
        for (t8x8, coded) in [(true, true), (false, true), (false, false)] {
            let mut dec = InterDecision {
                mvd: [crate::h264::frame::Mv::new(5, -9); 16],
                transform_8x8: t8x8 && coded,
                ..InterDecision::default()
            };
            if coded {
                if t8x8 {
                    let mut b = [0i16; 64];
                    for (i, v) in b.iter_mut().enumerate() {
                        *v = ((i as i16 % 5) - 2) * if i % 3 == 0 { 2 } else { -1 };
                    }
                    dec.luma.as_flattened_mut()[64..128].copy_from_slice(&b);
                    let counts = sub_block_counts_8x8_scan(&b, false);
                    for (sub, &r) in quad_rasters(1).iter().enumerate() {
                        dec.nz_luma[r] = counts[sub];
                    }
                    dec.cbp_luma = 0b0010;
                } else {
                    dec.luma[2][0] = 5;
                    dec.luma[2][7] = -2;
                    dec.nz_luma[2] = 2;
                    dec.cbp_luma = 0b0010;
                }
                dec.chroma_dc[1][0] = -3;
                dec.cbp_chroma = 1;
            }

            let mut st = NzState::new(1, 2, false);
            let mut w = BitWriter::new();
            write_p16_macroblock(&mut w, &dec, &mut st, 0, false, false, true, false);
            w.rbsp_trailing_bits();
            let rbsp = w.into_rbsp();

            let ctx = SliceCtx {
                transform_8x8_mode: true,
                ..p_ctx()
            };
            let info = PicInfo::new(1, 1);
            let nb = MbNeighbours {
                mb_width: 1,
                ..MbNeighbours::default()
            };
            let dq = Dequant::new(&flat());
            let mut qps = QpState {
                prev_qp: 28,
                chroma_offset: [0, 0],
            };
            let mut r = BitReader::new(&rbsp);
            let t = r.ue();
            let mut layer = MbLayer::new(DecKind::I4x4);
            parse_mb_cavlc(&mut r, &ctx, &info, &nb, t, &mut layer, &dq, &mut qps)
                .expect("the reader rejected what the writer produced");
            assert!(!r.overrun());
            assert_eq!(layer.kind, DecKind::Inter16x16);
            assert_eq!(
                layer.transform_8x8, dec.transform_8x8,
                "t8x8={t8x8} coded={coded}"
            );
            assert_eq!(layer.cbp, dec.cbp_luma | (dec.cbp_chroma << 4));
            assert_eq!(
                layer.nz[0], dec.nz_luma,
                "t8x8={t8x8} coded={coded} luma nz"
            );
            // The reader scales as it parses, so the levels come back
            // dequantised — and asking *it* for the table and shift is
            // what pins the 8x8 inter scaling list (index 1, since the
            // 8x8 lists run `2 * plane + inter`) and the `qP / 6` shift.
            let mbdq = crate::h264::mb::MbDequant::for_mb(
                &dq,
                &ctx,
                [0, 0],
                DecKind::Inter16x16,
                layer.qp,
            )
            .expect("not lossless");
            let (table, shift) = mbdq.q8[0];
            for i in 0..256 {
                let want = if dec.transform_8x8 {
                    crate::h264::mb::dequant_level(
                        dec.luma.as_flattened()[i] as i32,
                        table[i % 64],
                        shift,
                    )
                } else {
                    let (blk, k) = (i / 16, i % 16);
                    crate::h264::mb::dequant_level(
                        dec.luma[blk][k] as i32,
                        mbdq.q4[0].0[k],
                        mbdq.q4[0].1,
                    )
                };
                assert_eq!(
                    layer.coef[0][i], want,
                    "t8x8={t8x8} coded={coded} coeff {i}"
                );
            }
        }
    }

    /// A hand-built I_4x4 decision, so the writer's I_NxN syntax — the
    /// sixteen mode elements, the me(v) coded block pattern and the
    /// full-span residual blocks — is exercised whatever the mode
    /// decision above happens to choose. All modes DC keeps the
    /// prediction bookkeeping trivially consistent with an isolated
    /// macroblock, whose every predicted mode is DC.
    #[test]
    fn a_synthetic_i4x4_macroblock_round_trips() {
        let mut dec = MbDecision {
            kind: MbKind::I4x4,
            luma_pred: [PredMode {
                use_predicted: true,
                rem: 0,
            }; 16],
            chroma_mode: 1,
            ..MbDecision::default()
        };
        // Blocks 0 and 5 coded (both in luma 8x8 block 0), block 15 too,
        // with counts the levels really have.
        dec.luma[0][0] = 7;
        dec.luma[0][3] = -2;
        dec.luma[0][10] = 1;
        dec.nz_luma[0] = 3;
        dec.luma[5][1] = -1;
        dec.nz_luma[5] = 1;
        dec.luma[15][0] = 4;
        dec.luma[15][15] = 1;
        dec.nz_luma[15] = 2;
        dec.cbp_luma = 0b1001;
        // Chroma: DC on both components, AC on Cb block 2.
        dec.chroma_dc[0][0] = 3;
        dec.chroma_dc[0][2] = -1;
        dec.chroma_dc[1][1] = 2;
        dec.chroma_ac[0][2][5] = -4;
        dec.chroma_ac[0][2][1] = 1;
        dec.nz_chroma[0][2] = 2;
        dec.cbp_chroma = 2;
        let modes = [2u8; 16];
        round_trip(&dec, Some(&modes), 28);
    }
}
