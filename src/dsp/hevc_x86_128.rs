//! 128-bit SIMD versions of the H.265 kernels (x86-64), for CPUs without AVX2.
//!
//! Half the lanes of [`super::hevc_avx2`] / [`super::hevc_avx2_u8`] and the
//! same arithmetic. Two things make the narrower vector cost less than the
//! width suggests: at 128 bits `packs_epi32` / `packus_epi16` already land
//! their results in order, so every cross-lane `permute4x64` the 256-bit
//! kernels need to undo per-lane packing disappears; and the AVX2 kernels
//! already fall back to a 128-bit body for `w <= 8`, which is most chroma
//! and every small PU.
//!
//! Both sample widths live in one module so the 8-bit kernels can share the
//! 16-bit ones' deblocking filters, `store_n` / `load_n` and inverse
//! transform, exactly as the AVX2 pair does. The whole set is written once
//! and instantiated twice — SSE4.1 and AVX — by the `kernels_u16!` and
//! `kernels_u8!` macros; see [`super::h264_x86_128`] for why the second
//! instantiation is worth its code size.

#![cfg(target_arch = "x86_64")]

use super::Cpu;
use super::hevc::HevcDsp;
use crate::hevc::tables::TRANSFORM32;

/// The transform matrix rows for size `n` as interleaved pairs of rows
/// `(j, j+1)`: `[c[j][0], c[j+1][0], c[j][1], c[j+1][1], ...]` (n lanes × 2).
///
/// Shared by both instantiations — it is data, not code.
pub(crate) struct PairRows {
    rows32: [[i16; 64]; 16],
    rows16: [[i16; 32]; 8],
    rows8: [[i16; 16]; 4],
    rows4: [[i16; 8]; 2],
}

const fn build_pairs() -> PairRows {
    let mut p = PairRows {
        rows32: [[0; 64]; 16],
        rows16: [[0; 32]; 8],
        rows8: [[0; 16]; 4],
        rows4: [[0; 8]; 2],
    };
    let mut j = 0;
    while j < 16 {
        let mut k = 0;
        while k < 32 {
            p.rows32[j][2 * k] = TRANSFORM32[2 * j][k] as i16;
            p.rows32[j][2 * k + 1] = TRANSFORM32[2 * j + 1][k] as i16;
            k += 1;
        }
        j += 1;
    }
    let mut j = 0;
    while j < 8 {
        let mut k = 0;
        while k < 16 {
            p.rows16[j][2 * k] = TRANSFORM32[4 * j][k] as i16;
            p.rows16[j][2 * k + 1] = TRANSFORM32[4 * j + 2][k] as i16;
            k += 1;
        }
        j += 1;
    }
    let mut j = 0;
    while j < 4 {
        let mut k = 0;
        while k < 8 {
            p.rows8[j][2 * k] = TRANSFORM32[8 * j][k] as i16;
            p.rows8[j][2 * k + 1] = TRANSFORM32[8 * j + 4][k] as i16;
            k += 1;
        }
        j += 1;
    }
    let mut j = 0;
    while j < 2 {
        let mut k = 0;
        while k < 4 {
            p.rows4[j][2 * k] = TRANSFORM32[16 * j][k] as i16;
            p.rows4[j][2 * k + 1] = TRANSFORM32[16 * j + 8][k] as i16;
            k += 1;
        }
        j += 1;
    }
    p
}

pub(crate) static PAIRS: PairRows = build_pairs();

#[inline(always)]
pub(crate) fn pair_row(n: usize, j: usize) -> &'static [i16] {
    match n {
        32 => &PAIRS.rows32[j],
        16 => &PAIRS.rows16[j],
        8 => &PAIRS.rows8[j],
        _ => &PAIRS.rows4[j],
    }
}

/// The two level-dependent shapes that are particular to H.265: the byte FIR
/// the interpolation filters run on 8-bit planes, and the SAO edge-offset
/// lookup. Everything else level-dependent is in the `x86_compat` module.
macro_rules! codec_compat_hevc {
    ($feat:literal, sse2) => {
        /// The taps of a byte FIR, in the form this level multiplies by: one
        /// broadcast per tap, for `pmullw` on widened samples.
        struct Taps([__m128i; 8], usize);

        /// `taps[..n]` prepared for [`fir8`] / [`fir16`].
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn taps_load(taps: &[i8], n: usize) -> Taps {
            let mut v = [_mm_setzero_si128(); 8];
            for k in 0..n {
                v[k] = _mm_set1_epi16(taps[k] as i16);
            }
            Taps(v, n)
        }

        /// Eight consecutive FIR outputs from the u8 window at `p`, stepping
        /// `step` bytes per tap, as eight i16.
        ///
        /// `pmullw` keeps the low 16 bits, which is exact here: a single
        /// product is at most 255 · 58 = 14790 and no running sum of the
        /// HEVC luma or chroma taps leaves i16 for 8-bit input.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn fir8(p: *const u8, step: usize, t: &Taps) -> __m128i {
            unsafe {
                let mut acc = _mm_setzero_si128();
                for k in 0..t.1 {
                    let v = _mm_loadl_epi64(p.add(k * step) as *const __m128i);
                    acc = _mm_add_epi16(acc, _mm_mullo_epi16(zx8(v), t.0[k]));
                }
                acc
            }
        }

        /// Sixteen consecutive FIR outputs, as (low eight, high eight) i16.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn fir16(p: *const u8, step: usize, t: &Taps) -> (__m128i, __m128i) {
            unsafe {
                let mut lo = _mm_setzero_si128();
                let mut hi = _mm_setzero_si128();
                for k in 0..t.1 {
                    let v = _mm_loadu_si128(p.add(k * step) as *const __m128i);
                    lo = _mm_add_epi16(lo, _mm_mullo_epi16(zx8(v), t.0[k]));
                    hi = _mm_add_epi16(hi, _mm_mullo_epi16(zx8h(v), t.0[k]));
                }
                (lo, hi)
            }
        }

        /// The five SAO edge offsets, in the form this level looks them up.
        struct EdgeTab([__m128i; 5]);

        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn edge_tab(off: &[i16; 5]) -> EdgeTab {
            EdgeTab(std::array::from_fn(|i| _mm_set1_epi8(off[i] as i8)))
        }

        /// `off[e]` per byte lane, for `e` in 0..=4.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn edge_lut(t: &EdgeTab, e: __m128i) -> __m128i {
            unsafe {
                let mut o = _mm_setzero_si128();
                for i in 0..5 {
                    o = sel(o, t.0[i], _mm_cmpeq_epi8(e, _mm_set1_epi8(i as i8)));
                }
                o
            }
        }
    };

    // SSSE3 and above: `pmaddubsw` takes a pair of taps per instruction and
    // needs no widening, and `pshufb` is the offset table lookup.
    ($feat:literal, $lvl:tt) => {
        /// A pair of taps `(a, b)` as one 16-bit lane `a | b << 8` (the low
        /// byte multiplies the even sample of an interleaved pair).
        #[inline(always)]
        fn pair8(a: i8, b: i8) -> i16 {
            (a as u8 as i16) | ((b as i16) << 8)
        }

        /// The taps of a byte FIR as the tap pairs `pmaddubsw` wants, and how
        /// many pairs there are.
        struct Taps([__m128i; 4], usize);

        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn taps_load(taps: &[i8], n: usize) -> Taps {
            let mut v = [_mm_setzero_si128(); 4];
            for k in 0..n / 2 {
                v[k] = _mm_set1_epi16(pair8(taps[2 * k], taps[2 * k + 1]));
            }
            Taps(v, n / 2)
        }

        /// Eight consecutive FIR outputs from the u8 window at `p`, stepping
        /// `step` bytes per tap, as eight i16.
        ///
        /// `pmaddubsw` saturates its own pair sum, but no pair of HEVC taps
        /// can reach i16 for 8-bit input, and neither can the total.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn fir8(p: *const u8, step: usize, t: &Taps) -> __m128i {
            unsafe {
                let mut acc = _mm_setzero_si128();
                for k in 0..t.1 {
                    let a = _mm_loadl_epi64(p.add(2 * k * step) as *const __m128i);
                    let b = _mm_loadl_epi64(p.add((2 * k + 1) * step) as *const __m128i);
                    acc = _mm_add_epi16(acc, _mm_maddubs_epi16(_mm_unpacklo_epi8(a, b), t.0[k]));
                }
                acc
            }
        }

        /// Sixteen consecutive FIR outputs, as (low eight, high eight) i16.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn fir16(p: *const u8, step: usize, t: &Taps) -> (__m128i, __m128i) {
            unsafe {
                let mut lo = _mm_setzero_si128();
                let mut hi = _mm_setzero_si128();
                for k in 0..t.1 {
                    let a = _mm_loadu_si128(p.add(2 * k * step) as *const __m128i);
                    let b = _mm_loadu_si128(p.add((2 * k + 1) * step) as *const __m128i);
                    lo = _mm_add_epi16(lo, _mm_maddubs_epi16(_mm_unpacklo_epi8(a, b), t.0[k]));
                    hi = _mm_add_epi16(hi, _mm_maddubs_epi16(_mm_unpackhi_epi8(a, b), t.0[k]));
                }
                (lo, hi)
            }
        }

        /// The five SAO edge offsets as a `pshufb` table.
        struct EdgeTab(__m128i);

        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn edge_tab(off: &[i16; 5]) -> EdgeTab {
            let o = |i: usize| off[i] as i8;
            EdgeTab(_mm_setr_epi8(
                o(0),
                o(1),
                o(2),
                o(3),
                o(4),
                0,
                0,
                0,
                0,
                0,
                0,
                0,
                0,
                0,
                0,
                0,
            ))
        }

        /// `off[e]` per byte lane, for `e` in 0..=4.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn edge_lut(t: &EdgeTab, e: __m128i) -> __m128i {
            _mm_shuffle_epi8(t.0, e)
        }
    };
}

/// The 16-bit-sample kernels, plus everything the 8-bit ones share.
macro_rules! kernels_u16 {
    ($feat:literal, $lvl:tt) => {
        use std::arch::x86_64::*;

        use crate::dsp::hevc::HevcDsp;
        use crate::dsp::hevc_x86_128::pair_row;
        use crate::hevc::tables::{EPEL_FILTERS, QPEL_FILTERS, TRANSFORM32};

        crate::dsp::x86_compat::compat_core!($feat, $lvl);
        codec_compat_hevc!($feat, $lvl);

        // Install groups, split so a rung can replace only what it
        // changes; a rung that improves none of a group's primitives simply
        // does not call it and the rung below stays installed.

        /// Every 16-bit-sample kernel — the bottom rung, and the top one.
        pub(crate) fn install_all_u16(d: &mut HevcDsp<u16>) {
            d.idct = [idct::<4>, idct::<8>, idct::<16>, idct::<32>];
            d.idst4 = idst4;
            d.add_residual = add_residual;
            d.qpel_copy = copy_u16;
            d.qpel_h = qpel_h;
            d.qpel_v = qpel_v;
            d.qpel_v2 = qpel_v2;
            d.epel_copy = copy_u16;
            d.epel_h = epel_h;
            d.epel_v = epel_v;
            d.epel_v2 = epel_v2;
            d.uni = uni;
            d.bi = bi;
            d.weighted_uni = weighted_uni;
            d.weighted_bi = weighted_bi;
            d.qpel_uni = qpel_uni16;
            d.epel_uni = epel_uni16;
            d.qpel_bi = qpel_bi16;
            d.epel_bi = epel_bi16;
            d.fused_mc = true;
            d.intra_planar = intra_planar::<u16>;
            d.intra_dc = intra_dc::<u16>;
            d.intra_angular = intra_angular::<u16>;
            install_sao_u16(d);
            install_deblock_u16(d);
        }

        /// SAO band and edge offset (lane selects).
        pub(crate) fn install_sao_u16(d: &mut HevcDsp<u16>) {
            d.sao_band = sao_band;
            d.sao_edge = sao_edge;
        }

        /// The four loop-filter entries (`|x|`, lane selects, 32-bit min/max).
        pub(crate) fn install_deblock_u16(d: &mut HevcDsp<u16>) {
            d.deblock_luma_v = deblock_luma_v;
            d.deblock_luma_h = deblock_luma_h;
            d.deblock_chroma_v = deblock_chroma_v;
            d.deblock_chroma_h = deblock_chroma_h;
        }

        // ------------------------------------------------------------------
        // Helpers
        // ------------------------------------------------------------------

        /// A pair of taps `(a, b)` broadcast as 32-bit lanes `a | b << 16`.
        #[inline(always)]
        fn pair(a: i8, b: i8) -> i32 {
            (a as i16 as u16 as i32) | ((b as i16 as u16 as i32) << 16)
        }

        /// The same for 16-bit multiplicands: `pmaddwd` against `(x, y)`
        /// turns two interleaved i16 streams into `a·x + b·y` in i32 lanes,
        /// which is how the weighted combiners multiply without `pmulld`.
        #[inline(always)]
        fn pair16(a: i16, b: i16) -> i32 {
            (a as u16 as i32) | ((b as u16 as i32) << 16)
        }

        /// Store the first `n` (≤ 8) lanes of `v` to `dst`.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn store_n(dst: *mut i16, v: __m128i, n: usize) {
            unsafe {
                match n {
                    8 => _mm_storeu_si128(dst as *mut __m128i, v),
                    4 => _mm_storel_epi64(dst as *mut __m128i, v),
                    _ => {
                        let mut t = [0i16; 8];
                        _mm_storeu_si128(t.as_mut_ptr() as *mut __m128i, v);
                        std::ptr::copy_nonoverlapping(t.as_ptr(), dst, n);
                    }
                }
            }
        }

        /// Store the first `n` (≤ 8) lanes of `v` (u16 samples) to `dst`.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn store_n_u16(dst: *mut u16, v: __m128i, n: usize) {
            unsafe { store_n(dst as *mut i16, v, n) }
        }

        /// Load 8 lanes from `src`, or the first `avail` zero-padded.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn load_n(src: *const i16, avail: usize) -> __m128i {
            unsafe {
                if avail >= 8 {
                    _mm_loadu_si128(src as *const __m128i)
                } else if avail == 4 {
                    _mm_loadl_epi64(src as *const __m128i)
                } else {
                    let mut t = [0i16; 8];
                    std::ptr::copy_nonoverlapping(src, t.as_mut_ptr(), avail);
                    _mm_loadu_si128(t.as_ptr() as *const __m128i)
                }
            }
        }

        /// Whether reading `w` lanes into a row of `stride`, for `rows` rows,
        /// plus `extra` samples along, stays inside `len` for an 8-lane load.
        #[inline(always)]
        fn fits(len: usize, stride: usize, rows: usize, w: usize, extra: usize) -> bool {
            let last_x = if w == 0 { 0 } else { (w - 1) / 8 * 8 };
            (rows - 1) * stride + last_x + extra + 8 <= len
        }

        /// Clip 8 lanes of i16 to `0..=max` (max < 32768) as u16.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn clip_u16(v: __m128i, maxv: __m128i) -> __m128i {
            _mm_min_epi16(_mm_max_epi16(v, _mm_setzero_si128()), maxv)
        }

        /// What a FIR stage produces: 14-bit predictions (the two-pass path
        /// and the first stage of hv) ...
        const MODE_I16: u8 = 0;
        /// ... default-weighted uni-prediction samples ...
        const MODE_UNI: u8 = 1;
        /// ... or default-weighted bi-prediction samples.
        const MODE_BI: u8 = 2;

        /// Where a 16-bit-sample FIR stage writes, by `MODE_*`. The u8
        /// kernels bake the 8-bit shifts into their output stage; here the
        /// shift and the clip depend on the bit depth, so they travel with
        /// the destination.
        #[derive(Clone, Copy)]
        struct Out16 {
            /// `MODE_I16`: 14-bit predictions, stride `w`.
            i16: *mut i16,
            /// `MODE_UNI` / `MODE_BI`: samples, stride `stride`.
            dst: *mut u16,
            /// Sample stride.
            stride: usize,
            /// `MODE_BI`: the other list's 14-bit prediction, stride `w`.
            other: *const i16,
            /// Block width (the stride of `i16` and `other`).
            w: usize,
            /// `14 - BitDepth` (uni) or `15 - BitDepth` (bi).
            shift: i32,
            /// `(1 << BitDepth) - 1`.
            max: i32,
        }

        impl Out16 {
            /// 14-bit predictions into `dst`, stride `w`.
            fn i16(dst: *mut i16, w: usize) -> Self {
                Out16 {
                    i16: dst,
                    dst: std::ptr::null_mut(),
                    stride: 0,
                    other: std::ptr::null(),
                    w,
                    shift: 0,
                    max: 0,
                }
            }
        }

        /// Emit 8 lanes of a stage's output (`v`, 14-bit) at (`row`, `x`),
        /// the first `n` lanes: stored as they are, or finished the way
        /// [`uni`] / [`bi`] finish a stored prediction, lane for lane.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn emit16<const MODE: u8>(out: &Out16, row: usize, x: usize, v: __m128i, n: usize) {
            unsafe {
                let sh = _mm_cvtsi32_si128(out.shift);
                let maxv = _mm_set1_epi16(out.max as i16);
                match MODE {
                    MODE_I16 => store_n(out.i16.add(row * out.w + x), v, n),
                    MODE_UNI => {
                        // 14-bit + round fits i16 (< 16384 + 8192).
                        let r = _mm_sra_epi16(
                            _mm_adds_epi16(v, _mm_set1_epi16(1 << (out.shift - 1))),
                            sh,
                        );
                        store_n_u16(out.dst.add(row * out.stride + x), clip_u16(r, maxv), n);
                    }
                    _ => {
                        // The sum can pass i16: `pmaddwd` against (1, 1) is it
                        // in 32 bits.
                        let o = load_n(out.other.add(row * out.w + x), n);
                        let ones = _mm_set1_epi32(pair16(1, 1));
                        let round = _mm_set1_epi32(1 << (out.shift - 1));
                        let q = |u: __m128i| {
                            _mm_sra_epi32(_mm_add_epi32(_mm_madd_epi16(u, ones), round), sh)
                        };
                        let p = _mm_packs_epi32(
                            q(_mm_unpacklo_epi16(o, v)),
                            q(_mm_unpackhi_epi16(o, v)),
                        );
                        store_n_u16(out.dst.add(row * out.stride + x), clip_u16(p, maxv), n);
                    }
                }
            }
        }

        // ------------------------------------------------------------------
        // Interpolation
        // ------------------------------------------------------------------

        fn copy_u16(
            dst: &mut [i16],
            src: &[u16],
            src_stride: usize,
            w: usize,
            h: usize,
            shift: i32,
        ) {
            if !fits(src.len(), src_stride, h, w, 0) {
                return (HevcDsp::<u16>::SCALAR.qpel_copy)(dst, src, src_stride, w, h, shift);
            }
            unsafe { copy_u16_impl(dst, src, src_stride, w, h, shift) }
        }

        #[target_feature(enable = $feat)]
        unsafe fn copy_u16_impl(
            dst: &mut [i16],
            src: &[u16],
            src_stride: usize,
            w: usize,
            h: usize,
            shift: i32,
        ) {
            unsafe {
                let sh = _mm_cvtsi32_si128(shift);
                for y in 0..h {
                    let s = src.as_ptr().add(y * src_stride);
                    let d = dst.as_mut_ptr().add(y * w);
                    let mut x = 0;
                    while x < w {
                        let v = _mm_loadu_si128(s.add(x) as *const __m128i);
                        store_n(d.add(x), _mm_sll_epi16(v, sh), (w - x).min(8));
                        x += 8;
                    }
                }
            }
        }

        /// Horizontal FIR with `TAPS` taps over u16 samples.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn fir_h<const TAPS: usize, const MODE: u8>(
            out: &Out16,
            src: *const u16,
            src_stride: usize,
            w: usize,
            h: usize,
            taps: &[i8],
            shift: i32,
        ) {
            unsafe {
                let mut c = [_mm_setzero_si128(); 4];
                for k in 0..TAPS / 2 {
                    c[k] = _mm_set1_epi32(pair(taps[2 * k], taps[2 * k + 1]));
                }
                let sh = _mm_cvtsi32_si128(shift);
                for y in 0..h {
                    let s = src.add(y * src_stride);
                    let mut x = 0;
                    while x < w {
                        let mut lo = _mm_setzero_si128();
                        let mut hi = _mm_setzero_si128();
                        for k in 0..TAPS / 2 {
                            let a = _mm_loadu_si128(s.add(x + 2 * k) as *const __m128i);
                            let b = _mm_loadu_si128(s.add(x + 2 * k + 1) as *const __m128i);
                            lo = _mm_add_epi32(lo, _mm_madd_epi16(_mm_unpacklo_epi16(a, b), c[k]));
                            hi = _mm_add_epi32(hi, _mm_madd_epi16(_mm_unpackhi_epi16(a, b), c[k]));
                        }
                        let r = _mm_packs_epi32(_mm_sra_epi32(lo, sh), _mm_sra_epi32(hi, sh));
                        emit16::<MODE>(out, y, x, r, (w - x).min(8));
                        x += 8;
                    }
                }
            }
        }

        /// Vertical FIR with `TAPS` taps over u16 or i16 rows (`T` = 2-byte lanes).
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn fir_v<const TAPS: usize, T, const MODE: u8>(
            out: &Out16,
            src: *const T,
            src_stride: usize,
            w: usize,
            h: usize,
            taps: &[i8],
            shift: i32,
        ) {
            unsafe {
                let mut c = [_mm_setzero_si128(); 4];
                for k in 0..TAPS / 2 {
                    c[k] = _mm_set1_epi32(pair(taps[2 * k], taps[2 * k + 1]));
                }
                let sh = _mm_cvtsi32_si128(shift);
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let mut lo = _mm_setzero_si128();
                        let mut hi = _mm_setzero_si128();
                        for k in 0..TAPS / 2 {
                            let a = _mm_loadu_si128(
                                src.add((y + 2 * k) * src_stride + x) as *const __m128i
                            );
                            let b = _mm_loadu_si128(
                                src.add((y + 2 * k + 1) * src_stride + x) as *const __m128i
                            );
                            lo = _mm_add_epi32(lo, _mm_madd_epi16(_mm_unpacklo_epi16(a, b), c[k]));
                            hi = _mm_add_epi32(hi, _mm_madd_epi16(_mm_unpackhi_epi16(a, b), c[k]));
                        }
                        let r = _mm_packs_epi32(_mm_sra_epi32(lo, sh), _mm_sra_epi32(hi, sh));
                        emit16::<MODE>(out, y, x, r, (w - x).min(8));
                        x += 8;
                    }
                }
            }
        }

        fn qpel_h(
            dst: &mut [i16],
            src: &[u16],
            src_stride: usize,
            w: usize,
            h: usize,
            frac: usize,
            shift: i32,
        ) {
            if !fits(src.len(), src_stride, h, w, 8) {
                return (HevcDsp::<u16>::SCALAR.qpel_h)(dst, src, src_stride, w, h, frac, shift);
            }
            unsafe {
                fir_h::<8, MODE_I16>(
                    &Out16::i16(dst.as_mut_ptr(), w),
                    src.as_ptr(),
                    src_stride,
                    w,
                    h,
                    &QPEL_FILTERS[frac][..8],
                    shift,
                )
            }
        }

        fn qpel_v(
            dst: &mut [i16],
            src: &[u16],
            src_stride: usize,
            w: usize,
            h: usize,
            frac: usize,
            shift: i32,
        ) {
            if !fits(src.len(), src_stride, h + 7, w, 0) {
                return (HevcDsp::<u16>::SCALAR.qpel_v)(dst, src, src_stride, w, h, frac, shift);
            }
            unsafe {
                fir_v::<8, u16, MODE_I16>(
                    &Out16::i16(dst.as_mut_ptr(), w),
                    src.as_ptr(),
                    src_stride,
                    w,
                    h,
                    &QPEL_FILTERS[frac][..8],
                    shift,
                )
            }
        }

        pub(super) fn qpel_v2(
            dst: &mut [i16],
            src: &[i16],
            src_stride: usize,
            w: usize,
            h: usize,
            frac: usize,
        ) {
            if !fits(src.len(), src_stride, h + 7, w, 0) {
                return (HevcDsp::<u16>::SCALAR.qpel_v2)(dst, src, src_stride, w, h, frac);
            }
            unsafe {
                fir_v::<8, i16, MODE_I16>(
                    &Out16::i16(dst.as_mut_ptr(), w),
                    src.as_ptr(),
                    src_stride,
                    w,
                    h,
                    &QPEL_FILTERS[frac][..8],
                    6,
                )
            }
        }

        fn epel_h(
            dst: &mut [i16],
            src: &[u16],
            src_stride: usize,
            w: usize,
            h: usize,
            frac: usize,
            shift: i32,
        ) {
            if !fits(src.len(), src_stride, h, w, 4) {
                return (HevcDsp::<u16>::SCALAR.epel_h)(dst, src, src_stride, w, h, frac, shift);
            }
            unsafe {
                fir_h::<4, MODE_I16>(
                    &Out16::i16(dst.as_mut_ptr(), w),
                    src.as_ptr(),
                    src_stride,
                    w,
                    h,
                    &EPEL_FILTERS[frac],
                    shift,
                )
            }
        }

        fn epel_v(
            dst: &mut [i16],
            src: &[u16],
            src_stride: usize,
            w: usize,
            h: usize,
            frac: usize,
            shift: i32,
        ) {
            if !fits(src.len(), src_stride, h + 3, w, 0) {
                return (HevcDsp::<u16>::SCALAR.epel_v)(dst, src, src_stride, w, h, frac, shift);
            }
            unsafe {
                fir_v::<4, u16, MODE_I16>(
                    &Out16::i16(dst.as_mut_ptr(), w),
                    src.as_ptr(),
                    src_stride,
                    w,
                    h,
                    &EPEL_FILTERS[frac],
                    shift,
                )
            }
        }

        pub(super) fn epel_v2(
            dst: &mut [i16],
            src: &[i16],
            src_stride: usize,
            w: usize,
            h: usize,
            frac: usize,
        ) {
            if !fits(src.len(), src_stride, h + 3, w, 0) {
                return (HevcDsp::<u16>::SCALAR.epel_v2)(dst, src, src_stride, w, h, frac);
            }
            unsafe {
                fir_v::<4, i16, MODE_I16>(
                    &Out16::i16(dst.as_mut_ptr(), w),
                    src.as_ptr(),
                    src_stride,
                    w,
                    h,
                    &EPEL_FILTERS[frac],
                    6,
                )
            }
        }

        // ------------------------------------------------------------------
        // Fused interpolation + prediction
        // ------------------------------------------------------------------

        /// The whole-sample position: each sample shifted into the 14-bit
        /// domain as [`copy_u16`] does, then finished by `MODE`.
        #[target_feature(enable = $feat)]
        unsafe fn fir_copy<const MODE: u8>(
            out: &Out16,
            src: *const u16,
            src_stride: usize,
            w: usize,
            h: usize,
            shift: i32,
        ) {
            unsafe {
                let sh = _mm_cvtsi32_si128(shift);
                for y in 0..h {
                    let s = src.add(y * src_stride);
                    let mut x = 0;
                    while x < w {
                        let v = _mm_sll_epi16(_mm_loadu_si128(s.add(x) as *const __m128i), sh);
                        emit16::<MODE>(out, y, x, v, (w - x).min(8));
                        x += 8;
                    }
                }
            }
        }

        /// The fused kernels at 16 bits: `TAPS` (8 luma / 4 chroma),
        /// `MODE_UNI` or `MODE_BI`. The stages are the two-pass kernels'
        /// own, and the last one finishes its output where [`uni`] / [`bi`]
        /// would have read it back, so the 14-bit prediction is never
        /// stored. Bit depths 8 to 12, the ones whose intermediates are
        /// i16; the scalar reference takes anything else.
        #[allow(clippy::too_many_arguments)]
        fn fused16<const TAPS: usize, const MODE: u8>(
            dst: &mut [u16],
            dst_stride: usize,
            src: &[u16],
            src_stride: usize,
            w: usize,
            h: usize,
            fx: usize,
            fy: usize,
            tmp: &mut [i16],
            other: &[i16],
            bit_depth: u32,
        ) {
            let reach = TAPS / 2 - 1;
            let at_block = reach * src_stride + reach;
            let hh = h + TAPS - 1;
            let ok = (8..=12).contains(&bit_depth)
                && w >= 2
                && h >= 1
                && (h - 1) * dst_stride + w <= dst.len()
                && (MODE != MODE_BI || other.len() >= w * h)
                && tmp.len() >= crate::dsp::hevc::MC_TMP_LEN
                && match (fx, fy) {
                    (0, 0) => {
                        src.len() > at_block && fits(src.len() - at_block, src_stride, h, w, 0)
                    }
                    (_, 0) => {
                        src.len() > reach * src_stride
                            && fits(src.len() - reach * src_stride, src_stride, h, w, TAPS)
                    }
                    (0, _) => src.len() > reach && fits(src.len() - reach, src_stride, hh, w, 0),
                    _ => {
                        fits(src.len(), src_stride, hh, w, TAPS)
                            && fits(crate::dsp::hevc::MC_TMP_LEN, w, hh, w, 0)
                    }
                };
            if !ok {
                let s = HevcDsp::<u16>::SCALAR;
                return match (TAPS, MODE) {
                    (8, MODE_UNI) => (s.qpel_uni)(
                        dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, bit_depth,
                    ),
                    (8, _) => (s.qpel_bi)(
                        dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, other, bit_depth,
                    ),
                    (_, MODE_UNI) => (s.epel_uni)(
                        dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, bit_depth,
                    ),
                    _ => (s.epel_bi)(
                        dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, other, bit_depth,
                    ),
                };
            }
            let bd = bit_depth as i32;
            let shift1 = bd.min(12) - 8;
            let (tx, ty): (&[i8], &[i8]) = if TAPS == 8 {
                (&QPEL_FILTERS[fx][..8], &QPEL_FILTERS[fy][..8])
            } else {
                (&EPEL_FILTERS[fx], &EPEL_FILTERS[fy])
            };
            let out = Out16 {
                i16: std::ptr::null_mut(),
                dst: dst.as_mut_ptr(),
                stride: dst_stride,
                other: other.as_ptr(),
                w,
                shift: if MODE == MODE_UNI { 14 - bd } else { 15 - bd },
                max: (1 << bd) - 1,
            };
            unsafe {
                match (fx, fy) {
                    (0, 0) => fir_copy::<MODE>(
                        &out,
                        src.as_ptr().add(at_block),
                        src_stride,
                        w,
                        h,
                        14 - bd,
                    ),
                    (_, 0) => fir_h::<TAPS, MODE>(
                        &out,
                        src.as_ptr().add(reach * src_stride),
                        src_stride,
                        w,
                        h,
                        tx,
                        shift1,
                    ),
                    (0, _) => fir_v::<TAPS, u16, MODE>(
                        &out,
                        src.as_ptr().add(reach),
                        src_stride,
                        w,
                        h,
                        ty,
                        shift1,
                    ),
                    _ => {
                        fir_h::<TAPS, MODE_I16>(
                            &Out16::i16(tmp.as_mut_ptr(), w),
                            src.as_ptr(),
                            src_stride,
                            w,
                            hh,
                            tx,
                            shift1,
                        );
                        fir_v::<TAPS, i16, MODE>(&out, tmp.as_ptr(), w, w, h, ty, 6);
                    }
                }
            }
        }

        #[allow(clippy::too_many_arguments)]
        fn qpel_uni16(
            dst: &mut [u16],
            dst_stride: usize,
            src: &[u16],
            src_stride: usize,
            w: usize,
            h: usize,
            fx: usize,
            fy: usize,
            tmp: &mut [i16],
            bit_depth: u32,
        ) {
            fused16::<8, MODE_UNI>(
                dst,
                dst_stride,
                src,
                src_stride,
                w,
                h,
                fx,
                fy,
                tmp,
                &[],
                bit_depth,
            )
        }

        #[allow(clippy::too_many_arguments)]
        fn epel_uni16(
            dst: &mut [u16],
            dst_stride: usize,
            src: &[u16],
            src_stride: usize,
            w: usize,
            h: usize,
            fx: usize,
            fy: usize,
            tmp: &mut [i16],
            bit_depth: u32,
        ) {
            fused16::<4, MODE_UNI>(
                dst,
                dst_stride,
                src,
                src_stride,
                w,
                h,
                fx,
                fy,
                tmp,
                &[],
                bit_depth,
            )
        }

        #[allow(clippy::too_many_arguments)]
        fn qpel_bi16(
            dst: &mut [u16],
            dst_stride: usize,
            src: &[u16],
            src_stride: usize,
            w: usize,
            h: usize,
            fx: usize,
            fy: usize,
            tmp: &mut [i16],
            other: &[i16],
            bit_depth: u32,
        ) {
            fused16::<8, MODE_BI>(
                dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, other, bit_depth,
            )
        }

        #[allow(clippy::too_many_arguments)]
        fn epel_bi16(
            dst: &mut [u16],
            dst_stride: usize,
            src: &[u16],
            src_stride: usize,
            w: usize,
            h: usize,
            fx: usize,
            fy: usize,
            tmp: &mut [i16],
            other: &[i16],
            bit_depth: u32,
        ) {
            fused16::<4, MODE_BI>(
                dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, other, bit_depth,
            )
        }

        // ------------------------------------------------------------------
        // Intra prediction
        // ------------------------------------------------------------------
        //
        // Generic over the sample type: the reference samples are u16 for
        // both tables, the arithmetic is the same i16 / i32 lanes, and only
        // the store differs (`put`). `pmaddwd` reads the references as i16,
        // so a reference above 32767 (a 16-bit stream) goes to the scalar
        // kernel; no u8 reference can be.

        /// Store the first `n` (≤ 8) lanes of `v` (values in sample range)
        /// as samples of `S`.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn put<S: crate::hevc::frame::Sample>(dst: *mut S, v: __m128i, n: usize) {
            unsafe {
                if S::BYTES == 2 {
                    return store_n_u16(dst as *mut u16, v, n);
                }
                let b = _mm_packus_epi16(v, v);
                match n {
                    8 => _mm_storel_epi64(dst as *mut __m128i, b),
                    4 => std::ptr::write_unaligned(dst as *mut u32, _mm_cvtsi128_si32(b) as u32),
                    _ => {
                        let mut t = [0u8; 16];
                        _mm_storeu_si128(t.as_mut_ptr() as *mut __m128i, b);
                        std::ptr::copy_nonoverlapping(t.as_ptr(), dst as *mut u8, n);
                    }
                }
            }
        }

        /// Whether any of `r` is above 32767 — past what `pmaddwd` reads as
        /// a positive i16. Never true of a u8 table's references.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn over_i16<S: crate::hevc::frame::Sample>(r: &[u16]) -> bool {
            unsafe {
                if S::BYTES == 1 {
                    return false;
                }
                let mut acc = _mm_setzero_si128();
                let mut i = 0;
                while i + 8 <= r.len() {
                    acc = _mm_or_si128(acc, _mm_loadu_si128(r.as_ptr().add(i) as *const __m128i));
                    i += 8;
                }
                _mm_movemask_epi8(acc) & 0xAAAA != 0 || r[i..].iter().any(|&v| v > 32767)
            }
        }

        fn intra_planar<S: crate::hevc::frame::Sample>(
            dst: &mut [S],
            stride: usize,
            left: &[u16],
            top: &[u16],
            n: usize,
        ) {
            let fits = left.len() > n && top.len() >= n.max(8) && (n - 1) * stride + n <= dst.len();
            if !fits
                || !(4..=32).contains(&n)
                || unsafe { over_i16::<S>(&left[..=n]) || over_i16::<S>(&top[..=n]) }
            {
                return (HevcDsp::<S>::scalar().intra_planar)(dst, stride, left, top, n);
            }
            unsafe { intra_planar_impl(dst.as_mut_ptr(), stride, left, top, n) }
        }

        /// Planar, eight columns a vector: `(n-1-x)·p[-1][y] + (x+1)·p[n][-1]`
        /// is one `pmaddwd` of the per-column weight pairs against the
        /// broadcast pair `(left[y], top[n])`, and `(n-1-y)·p[x][-1] +
        /// (y+1)·p[-1][n]` another of the row's broadcast weights against
        /// `(top[x], left[n])` interleaved.
        #[target_feature(enable = $feat)]
        unsafe fn intra_planar_impl<S: crate::hevc::frame::Sample>(
            dst: *mut S,
            stride: usize,
            left: &[u16],
            top: &[u16],
            n: usize,
        ) {
            unsafe {
                let sh = _mm_cvtsi32_si128(n.trailing_zeros() as i32 + 1);
                let round = _mm_set1_epi32(n as i32);
                let ln = _mm_set1_epi16(left[n] as i16);
                let chunks = n.div_ceil(8);
                let mut w = [(_mm_setzero_si128(), _mm_setzero_si128()); 4];
                let mut t = [(_mm_setzero_si128(), _mm_setzero_si128()); 4];
                for c in 0..chunks {
                    let wx = |x: usize| pair16((n as i32 - 1 - x as i32) as i16, (x + 1) as i16);
                    let x0 = 8 * c;
                    w[c] = (
                        _mm_setr_epi32(wx(x0), wx(x0 + 1), wx(x0 + 2), wx(x0 + 3)),
                        _mm_setr_epi32(wx(x0 + 4), wx(x0 + 5), wx(x0 + 6), wx(x0 + 7)),
                    );
                    let tx = _mm_loadu_si128(top.as_ptr().add(x0) as *const __m128i);
                    t[c] = (_mm_unpacklo_epi16(tx, ln), _mm_unpackhi_epi16(tx, ln));
                }
                for y in 0..n {
                    let a = _mm_set1_epi32(pair16(left[y] as i16, top[n] as i16));
                    let b = _mm_set1_epi32(pair16((n - 1 - y) as i16, (y + 1) as i16));
                    for c in 0..chunks {
                        let lo = _mm_add_epi32(
                            _mm_add_epi32(_mm_madd_epi16(w[c].0, a), _mm_madd_epi16(t[c].0, b)),
                            round,
                        );
                        let hi = _mm_add_epi32(
                            _mm_add_epi32(_mm_madd_epi16(w[c].1, a), _mm_madd_epi16(t[c].1, b)),
                            round,
                        );
                        let v = _mm_packs_epi32(_mm_sra_epi32(lo, sh), _mm_sra_epi32(hi, sh));
                        put(dst.add(y * stride + 8 * c), v, (n - 8 * c).min(8));
                    }
                }
            }
        }

        fn intra_dc<S: crate::hevc::frame::Sample>(
            dst: &mut [S],
            stride: usize,
            left: &[u16],
            top: &[u16],
            n: usize,
            edge: bool,
        ) {
            if left.len() < n
                || top.len() < n
                || !(4..=32).contains(&n)
                || (n - 1) * stride + n > dst.len()
            {
                return (HevcDsp::<S>::scalar().intra_dc)(dst, stride, left, top, n, edge);
            }
            let log2n = n.trailing_zeros();
            let sum = n as i32
                + top[..n]
                    .iter()
                    .chain(&left[..n])
                    .map(|&v| v as i32)
                    .sum::<i32>();
            let dc = sum >> (log2n + 1);
            unsafe { intra_fill(dst.as_mut_ptr(), stride, n, dc) };
            if edge {
                dst[0] = S::from_i32((left[0] as i32 + 2 * dc + top[0] as i32 + 2) >> 2);
                for x in 1..n {
                    dst[x] = S::from_i32((top[x] as i32 + 3 * dc + 2) >> 2);
                }
                for y in 1..n {
                    dst[y * stride] = S::from_i32((left[y] as i32 + 3 * dc + 2) >> 2);
                }
            }
        }

        /// Fill an `n x n` block with `v` (a sample value).
        #[target_feature(enable = $feat)]
        unsafe fn intra_fill<S: crate::hevc::frame::Sample>(
            dst: *mut S,
            stride: usize,
            n: usize,
            v: i32,
        ) {
            unsafe {
                let vv = _mm_set1_epi16(v as i16);
                for y in 0..n {
                    let mut x = 0;
                    while x < n {
                        put(dst.add(y * stride + x), vv, (n - x).min(8));
                        x += 8;
                    }
                }
            }
        }

        pub(crate) fn intra_angular<S: crate::hevc::frame::Sample>(
            dst: &mut [S],
            stride: usize,
            refs: &[u16],
            n: usize,
            angle: i32,
            transposed: bool,
        ) {
            // Every load of the last vector of a row, from `ref[-n]` up.
            let reach = 3 * n + 2 + 8;
            if refs.len() < reach
                || !(4..=32).contains(&n)
                || (n - 1) * stride + n > dst.len()
                || unsafe { over_i16::<S>(&refs[..3 * n + 2]) }
            {
                return (HevcDsp::<S>::scalar().intra_angular)(
                    dst, stride, refs, n, angle, transposed,
                );
            }
            unsafe {
                intra_angular_impl(
                    dst.as_mut_ptr(),
                    stride,
                    refs.as_ptr(),
                    n,
                    angle,
                    transposed,
                )
            }
        }

        /// One row of the angular interpolation, eight samples at `p`
        /// (`ref[x + iIdx + 1]`) with fraction `f`: `pmaddwd` of the
        /// interleaved neighbours against `(32 - f, f)`.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn angular8(p: *const u16, k: __m128i, f: i32) -> __m128i {
            unsafe {
                let a = _mm_loadu_si128(p as *const __m128i);
                if f == 0 {
                    return a;
                }
                let b = _mm_loadu_si128(p.add(1) as *const __m128i);
                let r = _mm_set1_epi32(16);
                let lo = _mm_srai_epi32(
                    _mm_add_epi32(_mm_madd_epi16(_mm_unpacklo_epi16(a, b), k), r),
                    5,
                );
                let hi = _mm_srai_epi32(
                    _mm_add_epi32(_mm_madd_epi16(_mm_unpackhi_epi16(a, b), k), r),
                    5,
                );
                _mm_packs_epi32(lo, hi)
            }
        }

        /// Angular prediction. The vertical modes write their rows straight
        /// into the block; the horizontal ones predict the transposed block
        /// row by row into a scratch block, and an 8x8 (or 4x4) transpose
        /// per tile writes it into place.
        #[target_feature(enable = $feat)]
        unsafe fn intra_angular_impl<S: crate::hevc::frame::Sample>(
            dst: *mut S,
            stride: usize,
            refs: *const u16,
            n: usize,
            angle: i32,
            transposed: bool,
        ) {
            unsafe {
                // Written before it is read, tile by tile, so not cleared:
                // clearing 2 KB a call was a visible share of the kernel.
                let mut tmp = [std::mem::MaybeUninit::<u16>::uninit(); 32 * 32];
                for y in 0..n {
                    let pos = (y as i32 + 1) * angle;
                    let (i, f) = (pos >> 5, pos & 31);
                    let k = _mm_set1_epi32(pair16((32 - f) as i16, f as i16));
                    let p = refs.offset(n as isize + i as isize + 1);
                    let mut x = 0;
                    while x < n {
                        let v = angular8(p.add(x), k, f);
                        if transposed {
                            store_n(
                                tmp.as_mut_ptr().add(y * n + x) as *mut i16,
                                v,
                                (n - x).min(8),
                            );
                        } else {
                            put(dst.add(y * stride + x), v, (n - x).min(8));
                        }
                        x += 8;
                    }
                }
                if !transposed {
                    return;
                }
                let t = tmp.as_ptr() as *const u16;
                if n == 4 {
                    let r = |j: usize| _mm_loadl_epi64(t.add(4 * j) as *const __m128i);
                    let a = _mm_unpacklo_epi16(r(0), r(1));
                    let b = _mm_unpacklo_epi16(r(2), r(3));
                    let c01 = _mm_unpacklo_epi32(a, b);
                    let c23 = _mm_unpackhi_epi32(a, b);
                    put(dst, c01, 4);
                    put(dst.add(stride), _mm_srli_si128(c01, 8), 4);
                    put(dst.add(2 * stride), c23, 4);
                    put(dst.add(3 * stride), _mm_srli_si128(c23, 8), 4);
                    return;
                }
                for by in (0..n).step_by(8) {
                    for bx in (0..n).step_by(8) {
                        let mut r: [__m128i; 8] = std::array::from_fn(|j| {
                            _mm_loadu_si128(t.add((by + j) * n + bx) as *const __m128i)
                        });
                        transpose8_u16(&mut r);
                        for (j, v) in r.iter().enumerate() {
                            put(dst.add((bx + j) * stride + by), *v, 8);
                        }
                    }
                }
            }
        }

        // ------------------------------------------------------------------
        // Combination / weighting
        // ------------------------------------------------------------------

        fn uni(
            dst: &mut [u16],
            stride: usize,
            src: &[i16],
            w: usize,
            h: usize,
            shift: i32,
            max: i32,
        ) {
            unsafe { uni_impl(dst, stride, src, w, h, shift, max) }
        }

        #[target_feature(enable = $feat)]
        unsafe fn uni_impl(
            dst: &mut [u16],
            stride: usize,
            src: &[i16],
            w: usize,
            h: usize,
            shift: i32,
            max: i32,
        ) {
            unsafe {
                let round = _mm_set1_epi16(if shift > 0 { 1 << (shift - 1) } else { 0 });
                let sh = _mm_cvtsi32_si128(shift);
                let maxv = _mm_set1_epi16(max as i16);
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let n = (w - x).min(8);
                        let s = load_n(src.as_ptr().add(y * w + x), w - x);
                        // 14-bit + round fits i16 (< 16384 + 8192).
                        let v = _mm_sra_epi16(_mm_adds_epi16(s, round), sh);
                        store_n_u16(dst.as_mut_ptr().add(y * stride + x), clip_u16(v, maxv), n);
                        x += 8;
                    }
                }
            }
        }

        fn bi(
            dst: &mut [u16],
            stride: usize,
            a: &[i16],
            b: &[i16],
            w: usize,
            h: usize,
            shift: i32,
            max: i32,
        ) {
            unsafe { bi_impl(dst, stride, a, b, w, h, shift, max) }
        }

        #[target_feature(enable = $feat)]
        #[allow(clippy::too_many_arguments)]
        unsafe fn bi_impl(
            dst: &mut [u16],
            stride: usize,
            a: &[i16],
            b: &[i16],
            w: usize,
            h: usize,
            shift: i32,
            max: i32,
        ) {
            unsafe {
                let round = _mm_set1_epi32(1 << (shift - 1));
                let sh = _mm_cvtsi32_si128(shift);
                let maxv = _mm_set1_epi16(max as i16);
                // a + b can exceed i16, so the sum has to be 32-bit — but
                // `pmaddwd` against (1, 1) on the interleaved predictions is
                // exactly that sum, in one instruction and without widening.
                let ones = _mm_set1_epi32(pair16(1, 1));
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let n = (w - x).min(8);
                        let va = load_n(a.as_ptr().add(y * w + x), w - x);
                        let vb = load_n(b.as_ptr().add(y * w + x), w - x);
                        let quad = |v: __m128i| {
                            _mm_sra_epi32(_mm_add_epi32(_mm_madd_epi16(v, ones), round), sh)
                        };
                        let p = _mm_packs_epi32(
                            quad(_mm_unpacklo_epi16(va, vb)),
                            quad(_mm_unpackhi_epi16(va, vb)),
                        );
                        store_n_u16(dst.as_mut_ptr().add(y * stride + x), clip_u16(p, maxv), n);
                        x += 8;
                    }
                }
            }
        }

        #[allow(clippy::too_many_arguments)]
        fn weighted_uni(
            dst: &mut [u16],
            stride: usize,
            src: &[i16],
            w: usize,
            h: usize,
            log2_wd: i32,
            wt: i32,
            o: i32,
            max: i32,
        ) {
            // The `pmaddwd` form needs the weight as an i16 lane. HEVC bounds
            // it far inside that; anything else is the scalar reference's.
            if i16::try_from(wt).is_err() {
                return (HevcDsp::<u16>::SCALAR.weighted_uni)(
                    dst, stride, src, w, h, log2_wd, wt, o, max,
                );
            }
            unsafe { weighted_uni_impl(dst, stride, src, w, h, log2_wd, wt, o, max) }
        }

        #[target_feature(enable = $feat)]
        #[allow(clippy::too_many_arguments)]
        unsafe fn weighted_uni_impl(
            dst: &mut [u16],
            stride: usize,
            src: &[i16],
            w: usize,
            h: usize,
            log2_wd: i32,
            wt: i32,
            o: i32,
            max: i32,
        ) {
            unsafe {
                let round = _mm_set1_epi32(if log2_wd >= 1 { 1 << (log2_wd - 1) } else { 0 });
                let sh = _mm_cvtsi32_si128(log2_wd.max(0));
                // (wt, 0) against (s, 0) lanes: `pmaddwd` is the widening
                // multiply, so neither `pmulld` nor a sign-extension is needed.
                let wv = _mm_set1_epi32(pair16(wt as i16, 0));
                let ov = _mm_set1_epi32(o);
                let maxv = _mm_set1_epi16(max as i16);
                let zero = _mm_setzero_si128();
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let n = (w - x).min(8);
                        let s = load_n(src.as_ptr().add(y * w + x), w - x);
                        let quad = |v: __m128i| {
                            _mm_add_epi32(
                                _mm_sra_epi32(_mm_add_epi32(_mm_madd_epi16(v, wv), round), sh),
                                ov,
                            )
                        };
                        let p = _mm_packs_epi32(
                            quad(_mm_unpacklo_epi16(s, zero)),
                            quad(_mm_unpackhi_epi16(s, zero)),
                        );
                        store_n_u16(dst.as_mut_ptr().add(y * stride + x), clip_u16(p, maxv), n);
                        x += 8;
                    }
                }
            }
        }

        #[allow(clippy::too_many_arguments)]
        fn weighted_bi(
            dst: &mut [u16],
            stride: usize,
            a: &[i16],
            b: &[i16],
            w: usize,
            h: usize,
            log2_wd: i32,
            w0: i32,
            w1: i32,
            o0: i32,
            o1: i32,
            max: i32,
        ) {
            if i16::try_from(w0).is_err() || i16::try_from(w1).is_err() {
                return (HevcDsp::<u16>::SCALAR.weighted_bi)(
                    dst, stride, a, b, w, h, log2_wd, w0, w1, o0, o1, max,
                );
            }
            unsafe { weighted_bi_impl(dst, stride, a, b, w, h, log2_wd, w0, w1, o0, o1, max) }
        }

        #[target_feature(enable = $feat)]
        #[allow(clippy::too_many_arguments)]
        unsafe fn weighted_bi_impl(
            dst: &mut [u16],
            stride: usize,
            a: &[i16],
            b: &[i16],
            w: usize,
            h: usize,
            log2_wd: i32,
            w0: i32,
            w1: i32,
            o0: i32,
            o1: i32,
            max: i32,
        ) {
            unsafe {
                let round = _mm_set1_epi32((o0 + o1 + 1) << log2_wd);
                let sh = _mm_cvtsi32_si128(log2_wd + 1);
                // (w0, w1) against the two interleaved predictions: one
                // `pmaddwd` is `a·w0 + b·w1`, replacing two `pmulld` and an
                // add, and needing nothing above SSE2.
                let wv = _mm_set1_epi32(pair16(w0 as i16, w1 as i16));
                let maxv = _mm_set1_epi16(max as i16);
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let n = (w - x).min(8);
                        let va = load_n(a.as_ptr().add(y * w + x), w - x);
                        let vb = load_n(b.as_ptr().add(y * w + x), w - x);
                        let quad = |v: __m128i| {
                            _mm_sra_epi32(_mm_add_epi32(_mm_madd_epi16(v, wv), round), sh)
                        };
                        let p = _mm_packs_epi32(
                            quad(_mm_unpacklo_epi16(va, vb)),
                            quad(_mm_unpackhi_epi16(va, vb)),
                        );
                        store_n_u16(dst.as_mut_ptr().add(y * stride + x), clip_u16(p, maxv), n);
                        x += 8;
                    }
                }
            }
        }

        // ------------------------------------------------------------------
        // Residual add
        // ------------------------------------------------------------------

        fn add_residual(dst: &mut [u16], stride: usize, res: &[i16], n: usize, max: i32) {
            unsafe { add_residual_impl(dst, stride, res, n, max) }
        }

        #[target_feature(enable = $feat)]
        unsafe fn add_residual_impl(
            dst: &mut [u16],
            stride: usize,
            res: &[i16],
            n: usize,
            max: i32,
        ) {
            unsafe {
                let maxv = _mm_set1_epi16(max as i16);
                let zero = _mm_setzero_si128();
                if n >= 8 {
                    for y in 0..n {
                        let mut x = 0;
                        while x < n {
                            let d = dst.as_mut_ptr().add(y * stride + x);
                            let p = _mm_loadu_si128(d as *const __m128i);
                            let r = _mm_loadu_si128(res.as_ptr().add(y * n + x) as *const __m128i);
                            // Samples < 4096 and residuals fit: adds saturate correctly.
                            let v = _mm_min_epi16(_mm_max_epi16(_mm_adds_epi16(p, r), zero), maxv);
                            _mm_storeu_si128(d as *mut __m128i, v);
                            x += 8;
                        }
                    }
                } else {
                    // 4x4: two rows per 128-bit vector.
                    for y in (0..4).step_by(2) {
                        let d0 = dst.as_mut_ptr().add(y * stride);
                        let d1 = dst.as_mut_ptr().add((y + 1) * stride);
                        let p = _mm_unpacklo_epi64(
                            _mm_loadl_epi64(d0 as *const __m128i),
                            _mm_loadl_epi64(d1 as *const __m128i),
                        );
                        let r = _mm_loadu_si128(res.as_ptr().add(y * 4) as *const __m128i);
                        let v = _mm_min_epi16(_mm_max_epi16(_mm_adds_epi16(p, r), zero), maxv);
                        _mm_storel_epi64(d0 as *mut __m128i, v);
                        _mm_storel_epi64(d1 as *mut __m128i, _mm_unpackhi_epi64(v, v));
                    }
                }
            }
        }

        // ------------------------------------------------------------------
        // Inverse DCT
        // ------------------------------------------------------------------

        pub(super) fn idct<const N: usize>(
            coeffs: &mut [i16],
            bd_shift: i32,
            max_x: usize,
            max_y: usize,
        ) {
            if max_x == 0 && max_y == 0 {
                // DC only.
                let round2 = 1i32 << (bd_shift - 1);
                let v = ((coeffs[0] as i32 * 64 + 64) >> 7).clamp(-32768, 32767);
                let r = ((v * 64 + round2) >> bd_shift).clamp(-32768, 32767) as i16;
                coeffs[..N * N].fill(r);
                return;
            }
            if N == 4 {
                return idct4(coeffs, bd_shift, max_x, max_y);
            }
            unsafe { idct_impl::<N>(coeffs, bd_shift, max_x, max_y) }
        }

        /// The 4x4 DCT basis, `TRANSFORM32` at every eighth row.
        const DCT4: [[i16; 4]; 4] = [
            [64, 64, 64, 64],
            [83, 36, -36, -83],
            [64, -64, -64, 64],
            [36, -83, 83, -36],
        ];
        /// The 4x4 DST basis (8.6.4.2, `trType == 1`).
        const DST4: [[i16; 4]; 4] = [
            [29, 55, 74, 84],
            [74, 74, 0, -74],
            [84, -29, -74, 55],
            [55, -84, 74, -29],
        ];

        /// The 4x4 inverse DCT, all sixteen coefficients whatever `max_x` /
        /// `max_y` say (the rest are zero, and cost nothing here). The DC
        /// shortcut is `idct`'s. Shared with the AVX2 table, whose own
        /// kernel has nothing to widen at this size.
        pub(crate) fn idct4(coeffs: &mut [i16], bd_shift: i32, _max_x: usize, _max_y: usize) {
            assert!(coeffs.len() >= 16 && (1..=31).contains(&bd_shift));
            unsafe { inv4_impl(coeffs.as_mut_ptr(), bd_shift, &DCT4) }
        }

        /// The 4x4 inverse DST (intra luma 4x4).
        pub(crate) fn idst4(coeffs: &mut [i16], bd_shift: i32, _max_x: usize, _max_y: usize) {
            assert!(coeffs.len() >= 16 && (1..=31).contains(&bd_shift));
            unsafe { inv4_impl(coeffs.as_mut_ptr(), bd_shift, &DST4) }
        }

        /// One stage of a 4-point inverse transform over four vectors of
        /// four i16 (`r[j]`, coefficient `j` of four lines): output `i` of
        /// each line is `sum_j m[j][i] * r[j]` — two `pmaddwd` over the
        /// interleaved pairs `(r0, r1)` and `(r2, r3)` — then rounded,
        /// shifted and saturated to i16, which is the reference's clip.
        /// Returns outputs `[0 | 1]` and `[2 | 3]`.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn inv4_stage(
            r: [__m128i; 4],
            m: &[[i16; 4]; 4],
            round: __m128i,
            sh: __m128i,
        ) -> (__m128i, __m128i) {
            let p01 = _mm_unpacklo_epi16(r[0], r[1]);
            let p23 = _mm_unpacklo_epi16(r[2], r[3]);
            let out = |i: usize| {
                let a = _mm_madd_epi16(p01, _mm_set1_epi32(pair16(m[0][i], m[1][i])));
                let b = _mm_madd_epi16(p23, _mm_set1_epi32(pair16(m[2][i], m[3][i])));
                _mm_sra_epi32(_mm_add_epi32(_mm_add_epi32(a, b), round), sh)
            };
            (
                _mm_packs_epi32(out(0), out(1)),
                _mm_packs_epi32(out(2), out(3)),
            )
        }

        /// Transpose the 4x4 i16 block `[row0 | row1]`, `[row2 | row3]`
        /// into its columns, one each in the low half of a vector.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn columns4(a: __m128i, b: __m128i) -> [__m128i; 4] {
            let u = _mm_unpacklo_epi16(a, b);
            let v = _mm_unpackhi_epi16(a, b);
            let c01 = _mm_unpacklo_epi16(u, v);
            let c23 = _mm_unpackhi_epi16(u, v);
            [c01, _mm_srli_si128(c01, 8), c23, _mm_srli_si128(c23, 8)]
        }

        /// Both stages of the 4x4 inverse transform with basis `m` (8.6.4.2):
        /// columns, the 16-bit clip, rows. The second stage runs on the
        /// transposed intermediate, so its output is the block's columns
        /// and one more transpose puts it back in raster order.
        #[target_feature(enable = $feat)]
        unsafe fn inv4_impl(c: *mut i16, bd_shift: i32, m: &[[i16; 4]; 4]) {
            unsafe {
                let row = |j: usize| _mm_loadl_epi64(c.add(4 * j) as *const __m128i);
                let (a, b) = inv4_stage(
                    [row(0), row(1), row(2), row(3)],
                    m,
                    _mm_set1_epi32(64),
                    _mm_cvtsi32_si128(7),
                );
                let (a, b) = inv4_stage(
                    columns4(a, b),
                    m,
                    _mm_set1_epi32(1 << (bd_shift - 1)),
                    _mm_cvtsi32_si128(bd_shift),
                );
                let r = columns4(a, b);
                _mm_storeu_si128(c as *mut __m128i, _mm_unpacklo_epi64(r[0], r[1]));
                _mm_storeu_si128(c.add(8) as *mut __m128i, _mm_unpacklo_epi64(r[2], r[3]));
            }
        }

        #[target_feature(enable = $feat)]
        unsafe fn idct_impl<const N: usize>(
            coeffs: &mut [i16],
            bd_shift: i32,
            max_x: usize,
            max_y: usize,
        ) {
            unsafe {
                let mut tmp = [0i16; 32 * 32];
                // Stage 1 (columns): tmp[y][x] = clip((sum_j c[j][y] * coef[j][x] + 64) >> 7),
                // vectorised across x for each y; pairs of input rows (j, j+1).
                let nzy = max_y + 1;
                let npairs = nzy.div_ceil(2);
                let round1 = _mm_set1_epi32(64);
                let step = 32 / N;
                for y in 0..N {
                    let mut x = 0;
                    while x <= max_x {
                        let mut lo = round1;
                        let mut hi = round1;
                        for p in 0..npairs {
                            let j = 2 * p;
                            let a = load_n(coeffs.as_ptr().add(j * N + x), N - x);
                            let b = if j + 1 < nzy {
                                load_n(coeffs.as_ptr().add((j + 1) * N + x), N - x)
                            } else {
                                _mm_setzero_si128()
                            };
                            let c = _mm_set1_epi32(pair(
                                TRANSFORM32[j * step][y],
                                TRANSFORM32[(j + 1) * step][y],
                            ));
                            lo = _mm_add_epi32(lo, _mm_madd_epi16(_mm_unpacklo_epi16(a, b), c));
                            hi = _mm_add_epi32(hi, _mm_madd_epi16(_mm_unpackhi_epi16(a, b), c));
                        }
                        let r = _mm_packs_epi32(_mm_srai_epi32(lo, 7), _mm_srai_epi32(hi, 7));
                        store_n(tmp.as_mut_ptr().add(y * N + x), r, (N - x).min(8));
                        x += 8;
                    }
                }
                // Stage 2 (rows): out[y][x] = clip((sum_j c[j][x] * tmp[y][j] + round) >> shift),
                // vectorised across x with the interleaved pair rows of the matrix.
                let nzx = max_x + 1;
                let npairs = nzx.div_ceil(2);
                let round2 = _mm_set1_epi32(1 << (bd_shift - 1));
                let sh = _mm_cvtsi32_si128(bd_shift);
                for y in 0..N {
                    let row = tmp.as_ptr().add(y * N);
                    let mut x = 0;
                    while x < N {
                        let mut lo = round2;
                        let mut hi = round2;
                        for p in 0..npairs {
                            let j = 2 * p;
                            let t0 = *row.add(j) as i32;
                            let t1 = if j + 1 < nzx {
                                *row.add(j + 1) as i32
                            } else {
                                0
                            };
                            let tv =
                                _mm_set1_epi32((t0 as u16 as i32) | ((t1 as u16 as i32) << 16));
                            let pr = pair_row(N, p);
                            let cl = _mm_loadu_si128(pr.as_ptr().add(2 * x) as *const __m128i); // pairs for x..x+4
                            let ch = if N - x > 4 {
                                _mm_loadu_si128(pr.as_ptr().add(2 * x + 8) as *const __m128i)
                            } else {
                                _mm_setzero_si128()
                            };
                            lo = _mm_add_epi32(lo, _mm_madd_epi16(cl, tv));
                            hi = _mm_add_epi32(hi, _mm_madd_epi16(ch, tv));
                        }
                        // At 128 bits `packs` keeps outputs x..x+7 in order.
                        let r = _mm_packs_epi32(_mm_sra_epi32(lo, sh), _mm_sra_epi32(hi, sh));
                        store_n(coeffs.as_mut_ptr().add(y * N + x), r, (N - x).min(8));
                        x += 8;
                    }
                }
            }
        }

        // ------------------------------------------------------------------
        // SAO
        // ------------------------------------------------------------------

        #[allow(clippy::too_many_arguments)]
        fn sao_band(
            dst: &mut [u16],
            dst_stride: usize,
            src: &[u16],
            src_stride: usize,
            w: usize,
            h: usize,
            table: &[i16; 32],
            shift: i32,
            max: i32,
        ) {
            unsafe { sao_band_impl(dst, dst_stride, src, src_stride, w, h, table, shift, max) }
        }

        #[target_feature(enable = $feat)]
        #[allow(clippy::too_many_arguments)]
        unsafe fn sao_band_impl(
            dst: &mut [u16],
            dst_stride: usize,
            src: &[u16],
            src_stride: usize,
            w: usize,
            h: usize,
            table: &[i16; 32],
            shift: i32,
            max: i32,
        ) {
            unsafe {
                // The four consecutive bands (mod 32) with nonzero offsets.
                let mut bands = [0i16; 4];
                let mut offs = [0i16; 4];
                let mut k = 0;
                for b in 0..32 {
                    if table[b] != 0 && k < 4 {
                        bands[k] = b as i16;
                        offs[k] = table[b];
                        k += 1;
                    }
                }
                let sh = _mm_cvtsi32_si128(shift);
                let maxv = _mm_set1_epi16(max as i16);
                let bv: [__m128i; 4] = std::array::from_fn(|i| _mm_set1_epi16(bands[i]));
                let ov: [__m128i; 4] = std::array::from_fn(|i| _mm_set1_epi16(offs[i]));
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let n = (w - x).min(8);
                        let s = src.as_ptr().add(y * src_stride + x);
                        let v = if n == 8 {
                            _mm_loadu_si128(s as *const __m128i)
                        } else {
                            load_n(s as *const i16, n)
                        };
                        let band = _mm_srl_epi16(v, sh);
                        let mut off = _mm_setzero_si128();
                        for i in 0..k {
                            off = sel(off, ov[i], _mm_cmpeq_epi16(band, bv[i]));
                        }
                        let r = clip_u16(_mm_add_epi16(v, off), maxv);
                        store_n_u16(dst.as_mut_ptr().add(y * dst_stride + x), r, n);
                        x += 8;
                    }
                }
            }
        }

        #[allow(clippy::too_many_arguments)]
        fn sao_edge(
            dst: &mut [u16],
            src: &[u16],
            origin: usize,
            stride: usize,
            w: usize,
            h: usize,
            na: isize,
            nb: isize,
            off: &[i16; 5],
            max: i32,
        ) {
            unsafe { sao_edge_impl(dst, src, origin, stride, w, h, na, nb, off, max) }
        }

        #[target_feature(enable = $feat)]
        #[allow(clippy::too_many_arguments)]
        unsafe fn sao_edge_impl(
            dst: &mut [u16],
            src: &[u16],
            origin: usize,
            stride: usize,
            w: usize,
            h: usize,
            na: isize,
            nb: isize,
            off: &[i16; 5],
            max: i32,
        ) {
            unsafe {
                let maxv = _mm_set1_epi16(max as i16);
                let one = _mm_set1_epi16(1);
                // edgeIdx = 2 + sign(v-a) + sign(v-b) in 0..=4 → offsets via compares.
                let o0 = _mm_set1_epi16(off[0]);
                let o1 = _mm_set1_epi16(off[1]);
                let o3 = _mm_set1_epi16(off[3]);
                let o4 = _mm_set1_epi16(off[4]);
                let two = _mm_set1_epi16(2);
                let three = _mm_set1_epi16(3);
                let four = _mm_set1_epi16(4);
                let lo_reach = na.min(nb).min(0);
                let hi_reach = na.max(nb).max(0);
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let n = (w - x).min(8);
                        let i = origin + y * stride + x;
                        // All three loads and the store must stay inside.
                        if (i as isize + lo_reach) < 0
                            || (i as isize + hi_reach) as usize + 8 > src.len()
                            || i + 8 > dst.len()
                        {
                            // Tail near the buffer end: scalar.
                            for xx in x..w {
                                let ii = origin + y * stride + xx;
                                let v = src[ii] as i32;
                                let a = src[(ii as isize + na) as usize] as i32;
                                let b = src[(ii as isize + nb) as usize] as i32;
                                let e = (2 + (v - a).signum() + (v - b).signum()) as usize;
                                dst[ii] = (v + off[e] as i32).clamp(0, max) as u16;
                            }
                            break;
                        }
                        let v = _mm_loadu_si128(src.as_ptr().add(i) as *const __m128i);
                        let a =
                            _mm_loadu_si128(src.as_ptr().offset(i as isize + na) as *const __m128i);
                        let b =
                            _mm_loadu_si128(src.as_ptr().offset(i as isize + nb) as *const __m128i);
                        // sign(v - a) = (v > a) - (v < a); samples < 32768 so signed compares are exact.
                        let sa = _mm_sub_epi16(
                            _mm_and_si128(_mm_cmpgt_epi16(v, a), one),
                            _mm_and_si128(_mm_cmpgt_epi16(a, v), one),
                        );
                        let sb = _mm_sub_epi16(
                            _mm_and_si128(_mm_cmpgt_epi16(v, b), one),
                            _mm_and_si128(_mm_cmpgt_epi16(b, v), one),
                        );
                        let e = _mm_add_epi16(_mm_add_epi16(sa, sb), two);
                        let mut o = _mm_setzero_si128();
                        o = sel(o, o0, _mm_cmpeq_epi16(e, _mm_setzero_si128()));
                        o = sel(o, o1, _mm_cmpeq_epi16(e, one));
                        o = sel(o, o3, _mm_cmpeq_epi16(e, three));
                        o = sel(o, o4, _mm_cmpeq_epi16(e, four));
                        let r = clip_u16(_mm_add_epi16(v, o), maxv);
                        store_n_u16(dst.as_mut_ptr().add(i), r, n);
                        x += 8;
                    }
                }
            }
        }

        // ------------------------------------------------------------------
        // Deblocking
        // ------------------------------------------------------------------
        //
        // Four lines of an edge are four i32 lanes per sample position
        // (p3..q3), which holds every bit depth up to 12 without overflow —
        // and four lines is exactly one luma segment, so where the 256-bit
        // kernel filters two segments at once with per-segment lane masks,
        // this one runs the filter twice and the masks collapse to scalar
        // booleans. Chroma segments are two lines, so a vector still holds
        // two of them.

        /// Eight consecutive u16 as two vectors of 4 x i32 (lines 0..3, 4..7).
        #[target_feature(enable = $feat)]
        #[inline]
        pub(super) unsafe fn widen_u16(v: __m128i) -> (__m128i, __m128i) {
            unsafe { (zx16(v), zx16h(v)) }
        }

        /// Two vectors of 4 x i32 back to eight u16.
        ///
        /// Signed saturation, not `packusdw`: every lane the deblocking
        /// filters produce is a sample in `0..=max` — the untouched positions
        /// are originals, the weak filter clips explicitly, and the strong
        /// filter's `Clip3(p ± 2tc, avg)` cannot leave the range because
        /// `avg` is in it — and `max` is at most 4095, so the two saturations
        /// agree and this one needs only SSE2.
        #[target_feature(enable = $feat)]
        #[inline]
        pub(super) unsafe fn pack8_u16(lo: __m128i, hi: __m128i) -> __m128i {
            _mm_packs_epi32(lo, hi)
        }

        /// Transpose eight 8-lane u16 rows.
        #[target_feature(enable = $feat)]
        #[inline]
        pub(super) unsafe fn transpose8_u16(r: &mut [__m128i; 8]) {
            let a0 = _mm_unpacklo_epi16(r[0], r[1]);
            let a1 = _mm_unpackhi_epi16(r[0], r[1]);
            let a2 = _mm_unpacklo_epi16(r[2], r[3]);
            let a3 = _mm_unpackhi_epi16(r[2], r[3]);
            let a4 = _mm_unpacklo_epi16(r[4], r[5]);
            let a5 = _mm_unpackhi_epi16(r[4], r[5]);
            let a6 = _mm_unpacklo_epi16(r[6], r[7]);
            let a7 = _mm_unpackhi_epi16(r[6], r[7]);
            let b0 = _mm_unpacklo_epi32(a0, a2);
            let b1 = _mm_unpackhi_epi32(a0, a2);
            let b2 = _mm_unpacklo_epi32(a1, a3);
            let b3 = _mm_unpackhi_epi32(a1, a3);
            let b4 = _mm_unpacklo_epi32(a4, a6);
            let b5 = _mm_unpackhi_epi32(a4, a6);
            let b6 = _mm_unpacklo_epi32(a5, a7);
            let b7 = _mm_unpackhi_epi32(a5, a7);
            r[0] = _mm_unpacklo_epi64(b0, b4);
            r[1] = _mm_unpackhi_epi64(b0, b4);
            r[2] = _mm_unpacklo_epi64(b1, b5);
            r[3] = _mm_unpackhi_epi64(b1, b5);
            r[4] = _mm_unpacklo_epi64(b2, b6);
            r[5] = _mm_unpackhi_epi64(b2, b6);
            r[6] = _mm_unpacklo_epi64(b3, b7);
            r[7] = _mm_unpackhi_epi64(b3, b7);
        }

        /// The luma filter on one four-line segment, in place.
        #[target_feature(enable = $feat)]
        #[inline]
        pub(super) unsafe fn luma_filter4(
            v: &mut [__m128i; 8],
            beta: i32,
            tc: i32,
            no_p: bool,
            no_q: bool,
            max: i32,
        ) {
            unsafe {
                if beta == 0 && tc == 0 {
                    return;
                }
                let [p3, p2, p1, p0, q0, q1, q2, q3] = *v;
                let add = |a, b| _mm_add_epi32(a, b);
                let sub = |a, b| _mm_sub_epi32(a, b);
                let dbl = |a| _mm_slli_epi32(a, 1);
                let absd = |a, b| abs32(_mm_sub_epi32(a, b));
                // Lane-wise measures.
                let dpv = abs32(add(sub(p2, dbl(p1)), p0));
                let dqv = abs32(add(sub(q2, dbl(q1)), q0));
                let ev = add(absd(p3, p0), absd(q0, q3));
                let fv = absd(p0, q0);
                let mut dp = [0i32; 4];
                let mut dq = [0i32; 4];
                let mut e = [0i32; 4];
                let mut f = [0i32; 4];
                _mm_storeu_si128(dp.as_mut_ptr() as *mut __m128i, dpv);
                _mm_storeu_si128(dq.as_mut_ptr() as *mut __m128i, dqv);
                _mm_storeu_si128(e.as_mut_ptr() as *mut __m128i, ev);
                _mm_storeu_si128(f.as_mut_ptr() as *mut __m128i, fv);
                // The segment's decisions, from its lines 0 and 3.
                let dpq0 = dp[0] + dq[0];
                let dpq3 = dp[3] + dq[3];
                if dpq0 + dpq3 >= beta {
                    return;
                }
                let dsam = |l: usize, dpq: i32| {
                    dpq < (beta >> 2) && e[l] < (beta >> 3) && f[l] < ((5 * tc + 1) >> 1)
                };
                let strong = dsam(0, 2 * dpq0) && dsam(3, 2 * dpq3);
                let side = (beta + (beta >> 1)) >> 3;
                let dep = dp[0] + dp[3] < side;
                let deq = dq[0] + dq[3] < side;
                let zero = _mm_setzero_si128();
                let all = _mm_cmpeq_epi32(zero, zero);
                let m = |b: bool| if b { all } else { zero };
                let strong_m = m(strong);
                let dep_m = m(dep);
                let deq_m = m(deq);
                let wp_m = m(!no_p);
                let wq_m = m(!no_q);
                let tcv = _mm_set1_epi32(tc);
                let tc2 = dbl(tcv);
                let tch = _mm_srai_epi32(tcv, 1);
                // 10·tc, 9·x and 3·x as shifts and adds: SSE2, and shorter
                // latency than `pmulld` on the CPUs that have it.
                let tc10 = _mm_add_epi32(_mm_slli_epi32(tcv, 3), _mm_slli_epi32(tcv, 1));
                let maxv = _mm_set1_epi32(max);
                let clamp = |x, lo, hi| min32(max32(x, lo), hi);
                let two = _mm_set1_epi32(2);
                let four = _mm_set1_epi32(4);
                // Strong.
                let p0q0 = add(p0, q0);
                let sp0 = clamp(
                    _mm_srai_epi32(add(add(p2, dbl(add(p1, p0q0))), add(q1, four)), 3),
                    sub(p0, tc2),
                    add(p0, tc2),
                );
                let sp1 = clamp(
                    _mm_srai_epi32(add(add(p2, p1), add(p0q0, two)), 2),
                    sub(p1, tc2),
                    add(p1, tc2),
                );
                let sp2 = clamp(
                    _mm_srai_epi32(
                        add(add(dbl(p3), add(p2, dbl(p2))), add(add(p1, p0q0), four)),
                        3,
                    ),
                    sub(p2, tc2),
                    add(p2, tc2),
                );
                let sq0 = clamp(
                    _mm_srai_epi32(add(add(p1, dbl(add(p0q0, q1))), add(q2, four)), 3),
                    sub(q0, tc2),
                    add(q0, tc2),
                );
                let sq1 = clamp(
                    _mm_srai_epi32(add(add(p0q0, q1), add(q2, two)), 2),
                    sub(q1, tc2),
                    add(q1, tc2),
                );
                let sq2 = clamp(
                    _mm_srai_epi32(
                        add(add(p0q0, q1), add(add(q2, dbl(q2)), add(dbl(q3), four))),
                        3,
                    ),
                    sub(q2, tc2),
                    add(q2, tc2),
                );
                // Weak.
                let d0 = sub(q0, p0);
                let d1 = sub(q1, p1);
                let d0x9 = add(_mm_slli_epi32(d0, 3), d0);
                let d1x3 = add(_mm_slli_epi32(d1, 1), d1);
                let delta = _mm_srai_epi32(add(sub(d0x9, d1x3), _mm_set1_epi32(8)), 4);
                let w_m = _mm_cmpgt_epi32(tc10, abs32(delta));
                let delta = clamp(delta, sub(zero, tcv), tcv);
                let wp0 = clamp(add(p0, delta), zero, maxv);
                let wq0 = clamp(sub(q0, delta), zero, maxv);
                let one = _mm_set1_epi32(1);
                let dpv2 = clamp(
                    _mm_srai_epi32(
                        add(sub(_mm_srai_epi32(add(add(p2, p0), one), 1), p1), delta),
                        1,
                    ),
                    sub(zero, tch),
                    tch,
                );
                let dqv2 = clamp(
                    _mm_srai_epi32(
                        sub(sub(_mm_srai_epi32(add(add(q2, q0), one), 1), q1), delta),
                        1,
                    ),
                    sub(zero, tch),
                    tch,
                );
                let wp1 = clamp(add(p1, dpv2), zero, maxv);
                let wq1 = clamp(add(q1, dqv2), zero, maxv);
                // Combine: strong wins over weak; weak needs its per-line test.
                let np0 = sel(sel(p0, wp0, w_m), sp0, strong_m);
                let nq0 = sel(sel(q0, wq0, w_m), sq0, strong_m);
                let np1 = sel(sel(p1, wp1, _mm_and_si128(w_m, dep_m)), sp1, strong_m);
                let nq1 = sel(sel(q1, wq1, _mm_and_si128(w_m, deq_m)), sq1, strong_m);
                let np2 = sel(p2, sp2, strong_m);
                let nq2 = sel(q2, sq2, strong_m);
                v[1] = sel(p2, np2, wp_m);
                v[2] = sel(p1, np1, wp_m);
                v[3] = sel(p0, np0, wp_m);
                v[4] = sel(q0, nq0, wq_m);
                v[5] = sel(q1, nq1, wq_m);
                v[6] = sel(q2, nq2, wq_m);
            }
        }

        /// The chroma filter on four lines (two segments): `[p1, p0, q0, q1]`.
        #[target_feature(enable = $feat)]
        #[inline]
        pub(super) unsafe fn chroma_filter4(
            v: &mut [__m128i; 4],
            tc: [i32; 2],
            no_p: [bool; 2],
            no_q: [bool; 2],
            max: i32,
        ) {
            unsafe {
                let [p1, p0, q0, q1] = *v;
                let tcv = _mm_setr_epi32(tc[0], tc[0], tc[1], tc[1]);
                let m = |a: [bool; 2]| {
                    let x = |b: bool| -(b as i32);
                    _mm_setr_epi32(x(a[0]), x(a[0]), x(a[1]), x(a[1]))
                };
                let on = _mm_cmpgt_epi32(tcv, _mm_setzero_si128());
                let wp = _mm_andnot_si128(m(no_p), on);
                let wq = _mm_andnot_si128(m(no_q), on);
                let zero = _mm_setzero_si128();
                let maxv = _mm_set1_epi32(max);
                let d = _mm_srai_epi32(
                    _mm_add_epi32(
                        _mm_add_epi32(
                            _mm_slli_epi32(_mm_sub_epi32(q0, p0), 2),
                            _mm_sub_epi32(p1, q1),
                        ),
                        _mm_set1_epi32(4),
                    ),
                    3,
                );
                let d = min32(max32(d, _mm_sub_epi32(zero, tcv)), tcv);
                let np0 = min32(max32(_mm_add_epi32(p0, d), zero), maxv);
                let nq0 = min32(max32(_mm_sub_epi32(q0, d), zero), maxv);
                v[1] = sel(p0, np0, wp);
                v[2] = sel(q0, nq0, wq);
            }
        }

        #[allow(clippy::too_many_arguments)]
        fn deblock_luma_v(
            data: &mut [u16],
            off: usize,
            stride: usize,
            beta: [i32; 2],
            tc: [i32; 2],
            no_p: [bool; 2],
            no_q: [bool; 2],
            max: i32,
        ) {
            if (beta[0] == 0 && tc[0] == 0) && (beta[1] == 0 && tc[1] == 0) {
                return;
            }
            assert!(off >= 4 && off + 7 * stride + 4 <= data.len());
            unsafe {
                deblock_luma_v_impl(
                    data.as_mut_ptr().add(off),
                    stride,
                    beta,
                    tc,
                    no_p,
                    no_q,
                    max,
                )
            }
        }

        #[target_feature(enable = $feat)]
        #[allow(clippy::too_many_arguments)]
        unsafe fn deblock_luma_v_impl(
            data: *mut u16,
            stride: usize,
            beta: [i32; 2],
            tc: [i32; 2],
            no_p: [bool; 2],
            no_q: [bool; 2],
            max: i32,
        ) {
            unsafe {
                let mut r = [_mm_setzero_si128(); 8];
                for i in 0..8 {
                    r[i] = _mm_loadu_si128(data.add(i * stride).sub(4) as *const __m128i);
                }
                transpose8_u16(&mut r);
                let mut v0 = [_mm_setzero_si128(); 8];
                let mut v1 = [_mm_setzero_si128(); 8];
                for k in 0..8 {
                    let (a, b) = widen_u16(r[k]);
                    v0[k] = a;
                    v1[k] = b;
                }
                luma_filter4(&mut v0, beta[0], tc[0], no_p[0], no_q[0], max);
                luma_filter4(&mut v1, beta[1], tc[1], no_p[1], no_q[1], max);
                for k in 0..8 {
                    r[k] = pack8_u16(v0[k], v1[k]);
                }
                transpose8_u16(&mut r);
                for i in 0..8 {
                    _mm_storeu_si128(data.add(i * stride).sub(4) as *mut __m128i, r[i]);
                }
            }
        }

        #[allow(clippy::too_many_arguments)]
        fn deblock_luma_h(
            data: &mut [u16],
            off: usize,
            stride: usize,
            beta: [i32; 2],
            tc: [i32; 2],
            no_p: [bool; 2],
            no_q: [bool; 2],
            max: i32,
        ) {
            if (beta[0] == 0 && tc[0] == 0) && (beta[1] == 0 && tc[1] == 0) {
                return;
            }
            assert!(off >= 4 * stride && off + 3 * stride + 8 <= data.len());
            unsafe {
                deblock_luma_h_impl(
                    data.as_mut_ptr().add(off),
                    stride,
                    beta,
                    tc,
                    no_p,
                    no_q,
                    max,
                )
            }
        }

        #[target_feature(enable = $feat)]
        #[allow(clippy::too_many_arguments)]
        unsafe fn deblock_luma_h_impl(
            data: *mut u16,
            stride: usize,
            beta: [i32; 2],
            tc: [i32; 2],
            no_p: [bool; 2],
            no_q: [bool; 2],
            max: i32,
        ) {
            unsafe {
                let mut v0 = [_mm_setzero_si128(); 8];
                let mut v1 = [_mm_setzero_si128(); 8];
                for k in 0..8 {
                    let p = data.offset((k as isize - 4) * stride as isize);
                    v0[k] = zx16(_mm_loadl_epi64(p as *const __m128i));
                    v1[k] = zx16(_mm_loadl_epi64(p.add(4) as *const __m128i));
                }
                luma_filter4(&mut v0, beta[0], tc[0], no_p[0], no_q[0], max);
                luma_filter4(&mut v1, beta[1], tc[1], no_p[1], no_q[1], max);
                for k in 1..7 {
                    _mm_storeu_si128(
                        data.offset((k as isize - 4) * stride as isize) as *mut __m128i,
                        pack8_u16(v0[k], v1[k]),
                    );
                }
            }
        }

        fn deblock_chroma_v(
            data: &mut [u16],
            off: usize,
            stride: usize,
            tc: [i32; 4],
            no_p: [bool; 4],
            no_q: [bool; 4],
            max: i32,
        ) {
            if tc.iter().all(|&t| t == 0) {
                return;
            }
            assert!(off >= 2 && off + 7 * stride + 2 <= data.len());
            unsafe {
                deblock_chroma_v_impl(data.as_mut_ptr().add(off), stride, tc, no_p, no_q, max)
            }
        }

        #[target_feature(enable = $feat)]
        unsafe fn deblock_chroma_v_impl(
            data: *mut u16,
            stride: usize,
            tc: [i32; 4],
            no_p: [bool; 4],
            no_q: [bool; 4],
            max: i32,
        ) {
            unsafe {
                let mut r = [_mm_setzero_si128(); 8];
                for i in 0..8 {
                    r[i] = _mm_loadl_epi64(data.add(i * stride).sub(2) as *const __m128i);
                }
                let a0 = _mm_unpacklo_epi16(r[0], r[1]);
                let a1 = _mm_unpacklo_epi16(r[2], r[3]);
                let a2 = _mm_unpacklo_epi16(r[4], r[5]);
                let a3 = _mm_unpacklo_epi16(r[6], r[7]);
                let b0 = _mm_unpacklo_epi32(a0, a1); // p1 r0..3 | p0 r0..3
                let b1 = _mm_unpackhi_epi32(a0, a1); // q0 r0..3 | q1 r0..3
                let b2 = _mm_unpacklo_epi32(a2, a3); // rows 4..7
                let b3 = _mm_unpackhi_epi32(a2, a3);
                let col = |v: __m128i, hi: bool| if hi { zx16h(v) } else { zx16(v) };
                let mut v0 = [col(b0, false), col(b0, true), col(b1, false), col(b1, true)];
                let mut v1 = [col(b2, false), col(b2, true), col(b3, false), col(b3, true)];
                chroma_filter4(
                    &mut v0,
                    [tc[0], tc[1]],
                    [no_p[0], no_p[1]],
                    [no_q[0], no_q[1]],
                    max,
                );
                chroma_filter4(
                    &mut v1,
                    [tc[2], tc[3]],
                    [no_p[2], no_p[3]],
                    [no_q[2], no_q[3]],
                    max,
                );
                // (p0, q0) pairs per row, stored as one 32-bit write each.
                let p0 = pack8_u16(v0[1], v1[1]);
                let q0 = pack8_u16(v0[2], v1[2]);
                let lo = _mm_unpacklo_epi16(p0, q0); // rows 0..3
                let hi = _mm_unpackhi_epi16(p0, q0); // rows 4..7
                let mut t = [0u32; 8];
                _mm_storeu_si128(t.as_mut_ptr() as *mut __m128i, lo);
                _mm_storeu_si128(t.as_mut_ptr().add(4) as *mut __m128i, hi);
                for i in 0..8 {
                    std::ptr::write_unaligned(data.add(i * stride).sub(1) as *mut u32, t[i]);
                }
            }
        }

        fn deblock_chroma_h(
            data: &mut [u16],
            off: usize,
            stride: usize,
            tc: [i32; 4],
            no_p: [bool; 4],
            no_q: [bool; 4],
            max: i32,
        ) {
            if tc.iter().all(|&t| t == 0) {
                return;
            }
            assert!(off >= 2 * stride && off + stride + 8 <= data.len());
            unsafe {
                deblock_chroma_h_impl(data.as_mut_ptr().add(off), stride, tc, no_p, no_q, max)
            }
        }

        #[target_feature(enable = $feat)]
        unsafe fn deblock_chroma_h_impl(
            data: *mut u16,
            stride: usize,
            tc: [i32; 4],
            no_p: [bool; 4],
            no_q: [bool; 4],
            max: i32,
        ) {
            unsafe {
                let ld = |p: *const u16| -> (__m128i, __m128i) {
                    (
                        zx16(_mm_loadl_epi64(p as *const __m128i)),
                        zx16(_mm_loadl_epi64(p.add(4) as *const __m128i)),
                    )
                };
                let (a0, a1) = ld(data.sub(2 * stride));
                let (b0, b1) = ld(data.sub(stride));
                let (c0, c1) = ld(data);
                let (d0, d1) = ld(data.add(stride));
                let mut v0 = [a0, b0, c0, d0];
                let mut v1 = [a1, b1, c1, d1];
                chroma_filter4(
                    &mut v0,
                    [tc[0], tc[1]],
                    [no_p[0], no_p[1]],
                    [no_q[0], no_q[1]],
                    max,
                );
                chroma_filter4(
                    &mut v1,
                    [tc[2], tc[3]],
                    [no_p[2], no_p[3]],
                    [no_q[2], no_q[3]],
                    max,
                );
                _mm_storeu_si128(data.sub(stride) as *mut __m128i, pack8_u16(v0[1], v1[1]));
                _mm_storeu_si128(data as *mut __m128i, pack8_u16(v0[2], v1[2]));
            }
        }
    };
}

/// The 8-bit-sample kernels. Expanded into the same module as
/// [`kernels_u16!`], whose `store_n` / `load_n`, inverse transform and
/// deblocking filters they share — exactly as `hevc_avx2_u8` shares
/// `hevc_avx2`'s.
macro_rules! kernels_u8 {
    ($feat:literal, $lvl:tt) => {
        /// Every 8-bit-sample kernel — the bottom rung, and the top one.
        pub(crate) fn install_all_u8(d: &mut HevcDsp<u8>) {
            d.idct = [idct::<4>, idct::<8>, idct::<16>, idct::<32>];
            d.idst4 = idst4;
            d.intra_planar = intra_planar::<u8>;
            d.intra_dc = intra_dc::<u8>;
            d.intra_angular = intra_angular::<u8>;
            d.qpel_v2 = qpel_v2;
            d.epel_v2 = epel_v2;
            d.uni = uni_u8;
            d.bi = bi_u8;
            d.weighted_uni = weighted_uni_u8;
            d.weighted_bi = weighted_bi_u8;
            install_fir_u8(d);
            install_fused_u8(d);
            install_residual_u8(d);
            install_sao_band_u8(d);
            install_sao_edge_u8(d);
            install_deblock_u8(d);
        }

        /// The two-pass byte interpolation filters (the byte FIR).
        pub(crate) fn install_fir_u8(d: &mut HevcDsp<u8>) {
            d.qpel_h = qpel_h_u8;
            d.qpel_v = qpel_v_u8;
            d.epel_h = epel_h_u8;
            d.epel_v = epel_v_u8;
        }

        /// The fused interpolate-and-predict kernels, and the widening copy
        /// they and the two-pass path share.
        pub(crate) fn install_fused_u8(d: &mut HevcDsp<u8>) {
            d.qpel_copy = copy_u8;
            d.epel_copy = copy_u8;
            d.qpel_uni = qpel_uni_u8;
            d.epel_uni = epel_uni_u8;
            d.qpel_bi = qpel_bi_u8;
            d.epel_bi = epel_bi_u8;
            d.fused_mc = true;
        }

        /// Residual add (widening load).
        pub(crate) fn install_residual_u8(d: &mut HevcDsp<u8>) {
            d.add_residual = add_residual_u8;
        }

        /// SAO band offset (lane selects, signed byte max).
        pub(crate) fn install_sao_band_u8(d: &mut HevcDsp<u8>) {
            d.sao_band = sao_band_u8;
        }

        /// SAO edge offset (the offset table lookup).
        pub(crate) fn install_sao_edge_u8(d: &mut HevcDsp<u8>) {
            d.sao_edge = sao_edge_u8;
        }

        /// The four loop-filter entries.
        pub(crate) fn install_deblock_u8(d: &mut HevcDsp<u8>) {
            d.deblock_luma_v = deblock_luma_v_u8;
            d.deblock_luma_h = deblock_luma_h_u8;
            d.deblock_chroma_v = deblock_chroma_v_u8;
            d.deblock_chroma_h = deblock_chroma_h_u8;
        }

        // ------------------------------------------------------------------
        // Helpers
        // ------------------------------------------------------------------

        /// Store the first `n` (≤ 8) bytes of `v`.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn store_bytes(dst: *mut u8, v: __m128i, n: usize) {
            unsafe {
                match n {
                    8 => _mm_storel_epi64(dst as *mut __m128i, v),
                    4 => std::ptr::write_unaligned(dst as *mut u32, _mm_cvtsi128_si32(v) as u32),
                    2 => std::ptr::write_unaligned(dst as *mut u16, _mm_cvtsi128_si32(v) as u16),
                    _ => {
                        let mut t = [0u8; 16];
                        _mm_storeu_si128(t.as_mut_ptr() as *mut __m128i, v);
                        std::ptr::copy_nonoverlapping(t.as_ptr(), dst, n);
                    }
                }
            }
        }

        /// Store the first `n` (≤ 16) bytes of `v` (byte-lane kernels: SAO).
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn store_bytes16(dst: *mut u8, v: __m128i, n: usize) {
            unsafe {
                if n == 16 {
                    _mm_storeu_si128(dst as *mut __m128i, v);
                } else {
                    store_bytes(dst, v, n);
                }
            }
        }

        /// Load 16 bytes, or the first `avail` zero-padded.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn load_bytes16(src: *const u8, avail: usize) -> __m128i {
            unsafe {
                if avail >= 16 {
                    _mm_loadu_si128(src as *const __m128i)
                } else if avail == 8 {
                    _mm_loadl_epi64(src as *const __m128i)
                } else {
                    let mut t = [0u8; 16];
                    std::ptr::copy_nonoverlapping(src, t.as_mut_ptr(), avail);
                    _mm_loadu_si128(t.as_ptr() as *const __m128i)
                }
            }
        }

        /// 8 i16 lanes to 8 bytes, saturating to `0..=255`.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn pack8(v: __m128i) -> __m128i {
            _mm_packus_epi16(v, v)
        }

        /// Whether a block of width `w` is handled as one contiguous run of
        /// samples (the predictions are stored with stride `w`, so a 2- or
        /// 4-wide block is 4 or 2 rows per 8-lane vector instead of a mostly
        /// idle vector per row).
        #[inline(always)]
        fn narrow(w: usize) -> bool {
            w == 4 || w == 2
        }

        /// Store 8 bytes of `p` as `rows` rows of `w` (2 or 4) bytes.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn scatter_rows(dst: *mut u8, stride: usize, w: usize, p: __m128i, rows: usize) {
            unsafe {
                if w == 4 {
                    let mut t = [0u32; 4];
                    _mm_storeu_si128(t.as_mut_ptr() as *mut __m128i, p);
                    for r in 0..rows.min(2) {
                        std::ptr::write_unaligned(dst.add(r * stride) as *mut u32, t[r]);
                    }
                } else {
                    let mut t = [0u16; 8];
                    _mm_storeu_si128(t.as_mut_ptr() as *mut __m128i, p);
                    for r in 0..rows.min(4) {
                        std::ptr::write_unaligned(dst.add(r * stride) as *mut u16, t[r]);
                    }
                }
            }
        }

        /// Whether reading `w` bytes into a row of `stride`, for `rows` rows,
        /// plus `extra` bytes along, stays inside `len` for the vector width
        /// the byte kernels use at that block width.
        #[inline(always)]
        fn fits_b(len: usize, stride: usize, rows: usize, w: usize, extra: usize) -> bool {
            let (vec, last_x) = if w <= 8 {
                (8, 0)
            } else {
                (16, (w - 1) / 16 * 16)
            };
            (rows - 1) * stride + last_x + extra + vec <= len
        }

        /// Whether the second stage's `w`-stride 14-bit rows can be read 8
        /// lanes at a time for `rows` rows within `len`.
        #[inline(always)]
        fn fits_i16(len: usize, w: usize, rows: usize) -> bool {
            let last_x = if w <= 8 { 0 } else { (w - 1) / 8 * 8 };
            (rows - 1) * w + last_x + 8 <= len
        }

        // ------------------------------------------------------------------
        // Interpolation
        // ------------------------------------------------------------------

        /// What a FIR stage produces, per output kind (`MODE_*`).
        #[derive(Clone, Copy)]
        struct Out {
            /// `MODE_I16`: 14-bit predictions, stride `w`.
            i16: *mut i16,
            /// `MODE_UNI` / `MODE_BI`: samples, stride `stride`.
            u8: *mut u8,
            /// Sample stride.
            stride: usize,
            /// `MODE_BI`: the other list's 14-bit prediction, stride `w`.
            other: *const i16,
            /// Block width (the stride of `i16` and `other`).
            w: usize,
        }

        /// Emit 8 lanes of a stage's output (`v`, 14-bit) at (`row`, `x`), the
        /// first `n` lanes.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn emit<const MODE: u8>(out: &Out, row: usize, x: usize, v: __m128i, n: usize) {
            unsafe {
                match MODE {
                    MODE_I16 => store_n(out.i16.add(row * out.w + x), v, n),
                    MODE_UNI => {
                        let r = _mm_srai_epi16(_mm_adds_epi16(v, _mm_set1_epi16(32)), 6);
                        store_bytes(out.u8.add(row * out.stride + x), pack8(r), n);
                    }
                    _ => {
                        // Saturating sums, exact after the clip (see `bi_u8_impl`).
                        let o = load_n(out.other.add(row * out.w + x), n);
                        let r = _mm_srai_epi16(
                            _mm_adds_epi16(_mm_adds_epi16(v, o), _mm_set1_epi16(64)),
                            7,
                        );
                        store_bytes(out.u8.add(row * out.stride + x), pack8(r), n);
                    }
                }
            }
        }

        /// Horizontal FIR with `TAPS` taps over bytes.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn fir_h_u8<const TAPS: usize, const MODE: u8>(
            out: &Out,
            src: *const u8,
            src_stride: usize,
            w: usize,
            h: usize,
            taps: &[i8],
            shift: i32,
        ) {
            unsafe {
                let t = taps_load(taps, TAPS);
                let sh = _mm_cvtsi32_si128(shift);
                if w <= 8 {
                    // Narrow blocks: 8-byte loads, one vector per row.
                    for y in 0..h {
                        let acc = fir8(src.add(y * src_stride), 1, &t);
                        emit::<MODE>(out, y, 0, _mm_sra_epi16(acc, sh), w);
                    }
                    return;
                }
                for y in 0..h {
                    let s = src.add(y * src_stride);
                    let mut x = 0;
                    while x < w {
                        let (lo, hi) = fir16(s.add(x), 1, &t);
                        let n = w - x;
                        emit::<MODE>(out, y, x, _mm_sra_epi16(lo, sh), n.min(8));
                        if n > 8 {
                            emit::<MODE>(out, y, x + 8, _mm_sra_epi16(hi, sh), (n - 8).min(8));
                        }
                        x += 16;
                    }
                }
            }
        }

        /// Vertical FIR with `TAPS` taps over byte rows.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn fir_v_u8<const TAPS: usize, const MODE: u8>(
            out: &Out,
            src: *const u8,
            src_stride: usize,
            w: usize,
            h: usize,
            taps: &[i8],
            shift: i32,
        ) {
            unsafe {
                let t = taps_load(taps, TAPS);
                let sh = _mm_cvtsi32_si128(shift);
                let row = |r: usize| src.add(r * src_stride);
                if w <= 8 {
                    for y in 0..h {
                        let acc = fir8(row(y), src_stride, &t);
                        emit::<MODE>(out, y, 0, _mm_sra_epi16(acc, sh), w);
                    }
                    return;
                }
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let (lo, hi) = fir16(row(y).add(x), src_stride, &t);
                        let n = w - x;
                        emit::<MODE>(out, y, x, _mm_sra_epi16(lo, sh), n.min(8));
                        if n > 8 {
                            emit::<MODE>(out, y, x + 8, _mm_sra_epi16(hi, sh), (n - 8).min(8));
                        }
                        x += 16;
                    }
                }
            }
        }

        /// Vertical FIR with `TAPS` taps over 14-bit rows (the second stage of
        /// hv): `pmaddwd` on interleaved row pairs, 32-bit sums, `>> 6`.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn fir_v2_u8<const TAPS: usize, const MODE: u8>(
            out: &Out,
            src: *const i16,
            src_stride: usize,
            w: usize,
            h: usize,
            taps: &[i8],
        ) {
            unsafe {
                let mut c = [_mm_setzero_si128(); 4];
                for k in 0..TAPS / 2 {
                    c[k] = _mm_set1_epi32(pair(taps[2 * k], taps[2 * k + 1]));
                }
                let row = |r: usize| src.add(r * src_stride);
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let mut lo = _mm_setzero_si128();
                        let mut hi = _mm_setzero_si128();
                        for k in 0..TAPS / 2 {
                            let a = _mm_loadu_si128(row(y + 2 * k).add(x) as *const __m128i);
                            let b = _mm_loadu_si128(row(y + 2 * k + 1).add(x) as *const __m128i);
                            lo = _mm_add_epi32(lo, _mm_madd_epi16(_mm_unpacklo_epi16(a, b), c[k]));
                            hi = _mm_add_epi32(hi, _mm_madd_epi16(_mm_unpackhi_epi16(a, b), c[k]));
                        }
                        let r = _mm_packs_epi32(_mm_srai_epi32(lo, 6), _mm_srai_epi32(hi, 6));
                        emit::<MODE>(out, y, x, r, (w - x).min(8));
                        x += 8;
                    }
                }
            }
        }

        fn copy_u8(dst: &mut [i16], src: &[u8], src_stride: usize, w: usize, h: usize, shift: i32) {
            // 8-byte loads at every 8-sample step of each row.
            if (h - 1) * src_stride + (w - 1) / 8 * 8 + 8 > src.len() {
                return (HevcDsp::<u8>::SCALAR.qpel_copy)(dst, src, src_stride, w, h, shift);
            }
            unsafe { copy_u8_impl(dst, src, src_stride, w, h, shift) }
        }

        #[target_feature(enable = $feat)]
        unsafe fn copy_u8_impl(
            dst: &mut [i16],
            src: &[u8],
            src_stride: usize,
            w: usize,
            h: usize,
            shift: i32,
        ) {
            unsafe {
                let sh = _mm_cvtsi32_si128(shift);
                for y in 0..h {
                    let s = src.as_ptr().add(y * src_stride);
                    let d = dst.as_mut_ptr().add(y * w);
                    let mut x = 0;
                    while x < w {
                        let v = zx8(_mm_loadl_epi64(s.add(x) as *const __m128i));
                        store_n(d.add(x), _mm_sll_epi16(v, sh), (w - x).min(8));
                        x += 8;
                    }
                }
            }
        }

        fn qpel_h_u8(
            dst: &mut [i16],
            src: &[u8],
            src_stride: usize,
            w: usize,
            h: usize,
            frac: usize,
            shift: i32,
        ) {
            if !fits_b(src.len(), src_stride, h, w, 7) || dst.len() < w * h {
                return (HevcDsp::<u8>::SCALAR.qpel_h)(dst, src, src_stride, w, h, frac, shift);
            }
            let out = Out {
                i16: dst.as_mut_ptr(),
                u8: std::ptr::null_mut(),
                stride: 0,
                other: std::ptr::null(),
                w,
            };
            unsafe {
                fir_h_u8::<8, MODE_I16>(
                    &out,
                    src.as_ptr(),
                    src_stride,
                    w,
                    h,
                    &QPEL_FILTERS[frac][..8],
                    shift,
                )
            }
        }

        fn qpel_v_u8(
            dst: &mut [i16],
            src: &[u8],
            src_stride: usize,
            w: usize,
            h: usize,
            frac: usize,
            shift: i32,
        ) {
            if !fits_b(src.len(), src_stride, h + 7, w, 0) || dst.len() < w * h {
                return (HevcDsp::<u8>::SCALAR.qpel_v)(dst, src, src_stride, w, h, frac, shift);
            }
            let out = Out {
                i16: dst.as_mut_ptr(),
                u8: std::ptr::null_mut(),
                stride: 0,
                other: std::ptr::null(),
                w,
            };
            unsafe {
                fir_v_u8::<8, MODE_I16>(
                    &out,
                    src.as_ptr(),
                    src_stride,
                    w,
                    h,
                    &QPEL_FILTERS[frac][..8],
                    shift,
                )
            }
        }

        fn epel_h_u8(
            dst: &mut [i16],
            src: &[u8],
            src_stride: usize,
            w: usize,
            h: usize,
            frac: usize,
            shift: i32,
        ) {
            if !fits_b(src.len(), src_stride, h, w, 3) || dst.len() < w * h {
                return (HevcDsp::<u8>::SCALAR.epel_h)(dst, src, src_stride, w, h, frac, shift);
            }
            let out = Out {
                i16: dst.as_mut_ptr(),
                u8: std::ptr::null_mut(),
                stride: 0,
                other: std::ptr::null(),
                w,
            };
            unsafe {
                fir_h_u8::<4, MODE_I16>(
                    &out,
                    src.as_ptr(),
                    src_stride,
                    w,
                    h,
                    &EPEL_FILTERS[frac],
                    shift,
                )
            }
        }

        fn epel_v_u8(
            dst: &mut [i16],
            src: &[u8],
            src_stride: usize,
            w: usize,
            h: usize,
            frac: usize,
            shift: i32,
        ) {
            if !fits_b(src.len(), src_stride, h + 3, w, 0) || dst.len() < w * h {
                return (HevcDsp::<u8>::SCALAR.epel_v)(dst, src, src_stride, w, h, frac, shift);
            }
            let out = Out {
                i16: dst.as_mut_ptr(),
                u8: std::ptr::null_mut(),
                stride: 0,
                other: std::ptr::null(),
                w,
            };
            unsafe {
                fir_v_u8::<4, MODE_I16>(
                    &out,
                    src.as_ptr(),
                    src_stride,
                    w,
                    h,
                    &EPEL_FILTERS[frac],
                    shift,
                )
            }
        }

        // ------------------------------------------------------------------
        // Fused interpolation + prediction
        // ------------------------------------------------------------------

        /// Copy a `w x h` byte block (whole-sample uni-prediction: the
        /// prediction is the reference block).
        #[target_feature(enable = $feat)]
        unsafe fn copy_rows_u8(
            dst: *mut u8,
            dst_stride: usize,
            src: *const u8,
            src_stride: usize,
            w: usize,
            h: usize,
        ) {
            unsafe {
                for y in 0..h {
                    let s = src.add(y * src_stride);
                    let d = dst.add(y * dst_stride);
                    let mut x = 0;
                    while x < w {
                        let n = w - x;
                        if n >= 16 {
                            _mm_storeu_si128(
                                d.add(x) as *mut __m128i,
                                _mm_loadu_si128(s.add(x) as *const __m128i),
                            );
                            x += 16;
                        } else if n >= 8 {
                            _mm_storel_epi64(
                                d.add(x) as *mut __m128i,
                                _mm_loadl_epi64(s.add(x) as *const __m128i),
                            );
                            x += 8;
                        } else if n >= 4 {
                            std::ptr::write_unaligned(
                                d.add(x) as *mut u32,
                                std::ptr::read_unaligned(s.add(x) as *const u32),
                            );
                            x += 4;
                        } else {
                            std::ptr::write_unaligned(
                                d.add(x) as *mut u16,
                                std::ptr::read_unaligned(s.add(x) as *const u16),
                            );
                            x += 2;
                        }
                    }
                }
            }
        }

        /// The fused kernels: `TAPS` (8 luma / 4 chroma), `MODE_UNI` or `MODE_BI`.
        #[allow(clippy::too_many_arguments)]
        fn fused<const TAPS: usize, const MODE: u8>(
            dst: &mut [u8],
            dst_stride: usize,
            src: &[u8],
            src_stride: usize,
            w: usize,
            h: usize,
            fx: usize,
            fy: usize,
            tmp: &mut [i16],
            other: &[i16],
        ) {
            let reach = TAPS / 2 - 1;
            let at_block = reach * src_stride + reach;
            let hh = h + TAPS - 1;
            let ok = w >= 2
                && h >= 1
                && (h - 1) * dst_stride + w <= dst.len()
                && (MODE != MODE_BI || other.len() >= w * h)
                && tmp.len() >= crate::dsp::hevc::MC_TMP_LEN
                && match (fx, fy) {
                    (0, 0) => (h - 1) * src_stride + w + at_block <= src.len(),
                    (_, 0) => {
                        src.len() > reach * src_stride
                            && fits_b(src.len() - reach * src_stride, src_stride, h, w, TAPS - 1)
                    }
                    (0, _) => src.len() > reach && fits_b(src.len() - reach, src_stride, hh, w, 0),
                    _ => {
                        fits_b(src.len(), src_stride, hh, w, TAPS - 1)
                            && fits_i16(crate::dsp::hevc::MC_TMP_LEN, w, hh)
                    }
                };
            if !ok {
                let s = HevcDsp::<u8>::SCALAR;
                return match (TAPS, MODE) {
                    (8, MODE_UNI) => {
                        (s.qpel_uni)(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, 8)
                    }
                    (8, _) => (s.qpel_bi)(
                        dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, other, 8,
                    ),
                    (_, MODE_UNI) => {
                        (s.epel_uni)(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, 8)
                    }
                    _ => (s.epel_bi)(
                        dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, other, 8,
                    ),
                };
            }
            let (tx, ty): (&[i8], &[i8]) = if TAPS == 8 {
                (&QPEL_FILTERS[fx][..8], &QPEL_FILTERS[fy][..8])
            } else {
                (&EPEL_FILTERS[fx], &EPEL_FILTERS[fy])
            };
            let out = Out {
                i16: std::ptr::null_mut(),
                u8: dst.as_mut_ptr(),
                stride: dst_stride,
                other: other.as_ptr(),
                w,
            };
            unsafe {
                match (fx, fy) {
                    (0, 0) => {
                        if MODE == MODE_UNI {
                            copy_rows_u8(
                                dst.as_mut_ptr(),
                                dst_stride,
                                src.as_ptr().add(at_block),
                                src_stride,
                                w,
                                h,
                            );
                        } else {
                            // Whole-sample bi: widen, then the usual average.
                            let (pred, _) = tmp.split_at_mut(w * h);
                            copy_u8(pred, &src[at_block..], src_stride, w, h, 6);
                            bi_u8_impl(dst, dst_stride, other, pred, w, h, 7);
                        }
                    }
                    (_, 0) => fir_h_u8::<TAPS, MODE>(
                        &out,
                        src.as_ptr().add(reach * src_stride),
                        src_stride,
                        w,
                        h,
                        tx,
                        0,
                    ),
                    (0, _) => fir_v_u8::<TAPS, MODE>(
                        &out,
                        src.as_ptr().add(reach),
                        src_stride,
                        w,
                        h,
                        ty,
                        0,
                    ),
                    _ => {
                        let mid = Out {
                            i16: tmp.as_mut_ptr(),
                            u8: std::ptr::null_mut(),
                            stride: 0,
                            other: std::ptr::null(),
                            w,
                        };
                        fir_h_u8::<TAPS, MODE_I16>(&mid, src.as_ptr(), src_stride, w, hh, tx, 0);
                        fir_v2_u8::<TAPS, MODE>(&out, tmp.as_ptr(), w, w, h, ty);
                    }
                }
            }
        }

        fn qpel_uni_u8(
            dst: &mut [u8],
            dst_stride: usize,
            src: &[u8],
            src_stride: usize,
            w: usize,
            h: usize,
            fx: usize,
            fy: usize,
            tmp: &mut [i16],
            bit_depth: u32,
        ) {
            debug_assert_eq!(bit_depth, 8);
            fused::<8, MODE_UNI>(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, &[])
        }

        fn epel_uni_u8(
            dst: &mut [u8],
            dst_stride: usize,
            src: &[u8],
            src_stride: usize,
            w: usize,
            h: usize,
            fx: usize,
            fy: usize,
            tmp: &mut [i16],
            bit_depth: u32,
        ) {
            debug_assert_eq!(bit_depth, 8);
            fused::<4, MODE_UNI>(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, &[])
        }

        #[allow(clippy::too_many_arguments)]
        fn qpel_bi_u8(
            dst: &mut [u8],
            dst_stride: usize,
            src: &[u8],
            src_stride: usize,
            w: usize,
            h: usize,
            fx: usize,
            fy: usize,
            tmp: &mut [i16],
            other: &[i16],
            bit_depth: u32,
        ) {
            debug_assert_eq!(bit_depth, 8);
            fused::<8, MODE_BI>(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, other)
        }

        #[allow(clippy::too_many_arguments)]
        fn epel_bi_u8(
            dst: &mut [u8],
            dst_stride: usize,
            src: &[u8],
            src_stride: usize,
            w: usize,
            h: usize,
            fx: usize,
            fy: usize,
            tmp: &mut [i16],
            other: &[i16],
            bit_depth: u32,
        ) {
            debug_assert_eq!(bit_depth, 8);
            fused::<4, MODE_BI>(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, other)
        }

        // ------------------------------------------------------------------
        // Combination / weighting
        // ------------------------------------------------------------------

        fn uni_u8(
            dst: &mut [u8],
            stride: usize,
            src: &[i16],
            w: usize,
            h: usize,
            shift: i32,
            max: i32,
        ) {
            debug_assert_eq!(max, 255);
            unsafe { uni_u8_impl(dst, stride, src, w, h, shift) }
        }

        #[target_feature(enable = $feat)]
        unsafe fn uni_u8_impl(
            dst: &mut [u8],
            stride: usize,
            src: &[i16],
            w: usize,
            h: usize,
            shift: i32,
        ) {
            unsafe {
                let round = _mm_set1_epi16(if shift > 0 { 1 << (shift - 1) } else { 0 });
                let sh = _mm_cvtsi32_si128(shift);
                if narrow(w) {
                    let total = w * h;
                    let mut i = 0;
                    while i < total {
                        let n = (total - i).min(8);
                        let s = load_n(src.as_ptr().add(i), total - i);
                        let v = _mm_sra_epi16(_mm_adds_epi16(s, round), sh);
                        scatter_rows(
                            dst.as_mut_ptr().add((i / w) * stride),
                            stride,
                            w,
                            pack8(v),
                            n / w,
                        );
                        i += 8;
                    }
                    return;
                }
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let n = (w - x).min(8);
                        let s = load_n(src.as_ptr().add(y * w + x), w - x);
                        // 14-bit + round fits i16 (< 16384 + 8192).
                        let v = _mm_sra_epi16(_mm_adds_epi16(s, round), sh);
                        store_bytes(dst.as_mut_ptr().add(y * stride + x), pack8(v), n);
                        x += 8;
                    }
                }
            }
        }

        fn bi_u8(
            dst: &mut [u8],
            stride: usize,
            a: &[i16],
            b: &[i16],
            w: usize,
            h: usize,
            shift: i32,
            max: i32,
        ) {
            debug_assert_eq!(max, 255);
            unsafe { bi_u8_impl(dst, stride, a, b, w, h, shift) }
        }

        #[target_feature(enable = $feat)]
        unsafe fn bi_u8_impl(
            dst: &mut [u8],
            stride: usize,
            a: &[i16],
            b: &[i16],
            w: usize,
            h: usize,
            shift: i32,
        ) {
            unsafe {
                let round = _mm_set1_epi16(1 << (shift - 1));
                let sh = _mm_cvtsi32_si128(shift);
                if narrow(w) {
                    let total = w * h;
                    let mut i = 0;
                    while i < total {
                        let n = (total - i).min(8);
                        let va = load_n(a.as_ptr().add(i), total - i);
                        let vb = load_n(b.as_ptr().add(i), total - i);
                        let v = _mm_sra_epi16(_mm_adds_epi16(_mm_adds_epi16(va, vb), round), sh);
                        scatter_rows(
                            dst.as_mut_ptr().add((i / w) * stride),
                            stride,
                            w,
                            pack8(v),
                            n / w,
                        );
                        i += 8;
                    }
                    return;
                }
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let n = (w - x).min(8);
                        let va = load_n(a.as_ptr().add(y * w + x), w - x);
                        let vb = load_n(b.as_ptr().add(y * w + x), w - x);
                        // Saturating sums: a + b can exceed i16 only when both
                        // are far above the 8-bit range, and then the clip to
                        // 255 gives the same answer as the exact 32-bit sum.
                        let v = _mm_sra_epi16(_mm_adds_epi16(_mm_adds_epi16(va, vb), round), sh);
                        store_bytes(dst.as_mut_ptr().add(y * stride + x), pack8(v), n);
                        x += 8;
                    }
                }
            }
        }

        #[allow(clippy::too_many_arguments)]
        fn weighted_uni_u8(
            dst: &mut [u8],
            stride: usize,
            src: &[i16],
            w: usize,
            h: usize,
            log2_wd: i32,
            wt: i32,
            o: i32,
            max: i32,
        ) {
            debug_assert_eq!(max, 255);
            if i16::try_from(wt).is_err() {
                return (HevcDsp::<u8>::SCALAR.weighted_uni)(
                    dst, stride, src, w, h, log2_wd, wt, o, max,
                );
            }
            unsafe { weighted_uni_u8_impl(dst, stride, src, w, h, log2_wd, wt, o) }
        }

        #[target_feature(enable = $feat)]
        #[allow(clippy::too_many_arguments)]
        unsafe fn weighted_uni_u8_impl(
            dst: &mut [u8],
            stride: usize,
            src: &[i16],
            w: usize,
            h: usize,
            log2_wd: i32,
            wt: i32,
            o: i32,
        ) {
            unsafe {
                let round = _mm_set1_epi32(if log2_wd >= 1 { 1 << (log2_wd - 1) } else { 0 });
                let sh = _mm_cvtsi32_si128(log2_wd.max(0));
                let wv = _mm_set1_epi32(pair16(wt as i16, 0));
                let ov = _mm_set1_epi32(o);
                let zero = _mm_setzero_si128();
                let weigh = |s: __m128i| -> __m128i {
                    let quad = |v: __m128i| {
                        _mm_add_epi32(
                            _mm_sra_epi32(_mm_add_epi32(_mm_madd_epi16(v, wv), round), sh),
                            ov,
                        )
                    };
                    pack8(_mm_packs_epi32(
                        quad(_mm_unpacklo_epi16(s, zero)),
                        quad(_mm_unpackhi_epi16(s, zero)),
                    ))
                };
                if narrow(w) {
                    let total = w * h;
                    let mut i = 0;
                    while i < total {
                        let n = (total - i).min(8);
                        let s = load_n(src.as_ptr().add(i), total - i);
                        scatter_rows(
                            dst.as_mut_ptr().add((i / w) * stride),
                            stride,
                            w,
                            weigh(s),
                            n / w,
                        );
                        i += 8;
                    }
                    return;
                }
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let n = (w - x).min(8);
                        let s = load_n(src.as_ptr().add(y * w + x), w - x);
                        store_bytes(dst.as_mut_ptr().add(y * stride + x), weigh(s), n);
                        x += 8;
                    }
                }
            }
        }

        #[allow(clippy::too_many_arguments)]
        fn weighted_bi_u8(
            dst: &mut [u8],
            stride: usize,
            a: &[i16],
            b: &[i16],
            w: usize,
            h: usize,
            log2_wd: i32,
            w0: i32,
            w1: i32,
            o0: i32,
            o1: i32,
            max: i32,
        ) {
            debug_assert_eq!(max, 255);
            if i16::try_from(w0).is_err() || i16::try_from(w1).is_err() {
                return (HevcDsp::<u8>::SCALAR.weighted_bi)(
                    dst, stride, a, b, w, h, log2_wd, w0, w1, o0, o1, max,
                );
            }
            unsafe { weighted_bi_u8_impl(dst, stride, a, b, w, h, log2_wd, w0, w1, o0, o1) }
        }

        #[target_feature(enable = $feat)]
        #[allow(clippy::too_many_arguments)]
        unsafe fn weighted_bi_u8_impl(
            dst: &mut [u8],
            stride: usize,
            a: &[i16],
            b: &[i16],
            w: usize,
            h: usize,
            log2_wd: i32,
            w0: i32,
            w1: i32,
            o0: i32,
            o1: i32,
        ) {
            unsafe {
                let round = _mm_set1_epi32((o0 + o1 + 1) << log2_wd);
                let sh = _mm_cvtsi32_si128(log2_wd + 1);
                let wv = _mm_set1_epi32(pair16(w0 as i16, w1 as i16));
                let weigh = |va: __m128i, vb: __m128i| -> __m128i {
                    let quad =
                        |v: __m128i| _mm_sra_epi32(_mm_add_epi32(_mm_madd_epi16(v, wv), round), sh);
                    pack8(_mm_packs_epi32(
                        quad(_mm_unpacklo_epi16(va, vb)),
                        quad(_mm_unpackhi_epi16(va, vb)),
                    ))
                };
                if narrow(w) {
                    let total = w * h;
                    let mut i = 0;
                    while i < total {
                        let n = (total - i).min(8);
                        let va = load_n(a.as_ptr().add(i), total - i);
                        let vb = load_n(b.as_ptr().add(i), total - i);
                        scatter_rows(
                            dst.as_mut_ptr().add((i / w) * stride),
                            stride,
                            w,
                            weigh(va, vb),
                            n / w,
                        );
                        i += 8;
                    }
                    return;
                }
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let n = (w - x).min(8);
                        let va = load_n(a.as_ptr().add(y * w + x), w - x);
                        let vb = load_n(b.as_ptr().add(y * w + x), w - x);
                        store_bytes(dst.as_mut_ptr().add(y * stride + x), weigh(va, vb), n);
                        x += 8;
                    }
                }
            }
        }

        // ------------------------------------------------------------------
        // Residual add
        // ------------------------------------------------------------------

        fn add_residual_u8(dst: &mut [u8], stride: usize, res: &[i16], n: usize, max: i32) {
            debug_assert_eq!(max, 255);
            unsafe { add_residual_u8_impl(dst, stride, res, n) }
        }

        #[target_feature(enable = $feat)]
        unsafe fn add_residual_u8_impl(dst: &mut [u8], stride: usize, res: &[i16], n: usize) {
            unsafe {
                if n == 4 {
                    // 4x4: two rows per vector.
                    let d = dst.as_mut_ptr();
                    for y in (0..4).step_by(2) {
                        let rd = |k: usize| {
                            std::ptr::read_unaligned(d.add(k * stride) as *const u32) as i32
                        };
                        let p = zx8(_mm_setr_epi32(rd(y), rd(y + 1), 0, 0));
                        let r = _mm_loadu_si128(res.as_ptr().add(y * 4) as *const __m128i);
                        let v = _mm_packus_epi16(_mm_add_epi16(p, r), _mm_setzero_si128());
                        let mut t = [0u32; 4];
                        _mm_storeu_si128(t.as_mut_ptr() as *mut __m128i, v);
                        std::ptr::write_unaligned(d.add(y * stride) as *mut u32, t[0]);
                        std::ptr::write_unaligned(d.add((y + 1) * stride) as *mut u32, t[1]);
                    }
                    return;
                }
                for y in 0..n {
                    let mut x = 0;
                    while x < n {
                        let d = dst.as_mut_ptr().add(y * stride + x);
                        let p = zx8(_mm_loadl_epi64(d as *const __m128i));
                        let r = _mm_loadu_si128(res.as_ptr().add(y * n + x) as *const __m128i);
                        _mm_storel_epi64(
                            d as *mut __m128i,
                            _mm_packus_epi16(_mm_add_epi16(p, r), _mm_setzero_si128()),
                        );
                        x += 8;
                    }
                }
            }
        }

        // ------------------------------------------------------------------
        // SAO
        // ------------------------------------------------------------------

        /// `v + off` on bytes, clipped to `0..=255`, with `off` in `-128..=127`.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn add_offset_u8(v: __m128i, off: __m128i) -> __m128i {
            unsafe {
                let zero = _mm_setzero_si128();
                let pos = maxb0(off);
                let neg = maxb0(_mm_sub_epi8(zero, off));
                _mm_subs_epu8(_mm_adds_epu8(v, pos), neg)
            }
        }

        #[allow(clippy::too_many_arguments)]
        fn sao_band_u8(
            dst: &mut [u8],
            dst_stride: usize,
            src: &[u8],
            src_stride: usize,
            w: usize,
            h: usize,
            table: &[i16; 32],
            shift: i32,
            max: i32,
        ) {
            if shift != 3 || table.iter().any(|&o| !(-128..=127).contains(&o)) {
                return (HevcDsp::<u8>::SCALAR.sao_band)(
                    dst, dst_stride, src, src_stride, w, h, table, shift, max,
                );
            }
            debug_assert_eq!(max, 255);
            unsafe { sao_band_u8_impl(dst, dst_stride, src, src_stride, w, h, table, shift) }
        }

        #[target_feature(enable = $feat)]
        #[allow(clippy::too_many_arguments)]
        unsafe fn sao_band_u8_impl(
            dst: &mut [u8],
            dst_stride: usize,
            src: &[u8],
            src_stride: usize,
            w: usize,
            h: usize,
            table: &[i16; 32],
            shift: i32,
        ) {
            unsafe {
                // The four consecutive bands (mod 32) with nonzero offsets.
                let mut bands = [0u8; 4];
                let mut offs = [0i8; 4];
                let mut k = 0;
                for b in 0..32 {
                    if table[b] != 0 && k < 4 {
                        bands[k] = (b as u8) << shift;
                        offs[k] = table[b] as i8;
                        k += 1;
                    }
                }
                let mask = _mm_set1_epi8((0xFFu32 << shift) as u8 as i8);
                let bv: [__m128i; 4] = std::array::from_fn(|i| _mm_set1_epi8(bands[i] as i8));
                let ov: [__m128i; 4] = std::array::from_fn(|i| _mm_set1_epi8(offs[i]));
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let n = (w - x).min(16);
                        let v = load_bytes16(src.as_ptr().add(y * src_stride + x), n);
                        let band = _mm_and_si128(v, mask);
                        let mut off = _mm_setzero_si128();
                        for i in 0..k {
                            off = sel(off, ov[i], _mm_cmpeq_epi8(band, bv[i]));
                        }
                        store_bytes16(
                            dst.as_mut_ptr().add(y * dst_stride + x),
                            add_offset_u8(v, off),
                            n,
                        );
                        x += 16;
                    }
                }
            }
        }

        #[allow(clippy::too_many_arguments)]
        fn sao_edge_u8(
            dst: &mut [u8],
            src: &[u8],
            origin: usize,
            stride: usize,
            w: usize,
            h: usize,
            na: isize,
            nb: isize,
            off: &[i16; 5],
            max: i32,
        ) {
            if off.iter().any(|&o| !(-128..=127).contains(&o)) {
                return (HevcDsp::<u8>::SCALAR.sao_edge)(
                    dst, src, origin, stride, w, h, na, nb, off, max,
                );
            }
            debug_assert_eq!(max, 255);
            unsafe { sao_edge_u8_impl(dst, src, origin, stride, w, h, na, nb, off) }
        }

        #[target_feature(enable = $feat)]
        #[allow(clippy::too_many_arguments)]
        unsafe fn sao_edge_u8_impl(
            dst: &mut [u8],
            src: &[u8],
            origin: usize,
            stride: usize,
            w: usize,
            h: usize,
            na: isize,
            nb: isize,
            off: &[i16; 5],
        ) {
            unsafe {
                // edgeIdx = 2 + sign(v-a) + sign(v-b) in 0..=4 indexes the
                // offsets: one `pshufb` where there is one, else five selects.
                let tab = edge_tab(off);
                let two = _mm_set1_epi8(2);
                let lo_reach = na.min(nb).min(0);
                let hi_reach = na.max(nb).max(0);
                for y in 0..h {
                    let mut x = 0;
                    while x < w {
                        let n = (w - x).min(16);
                        let i = origin + y * stride + x;
                        if (i as isize + lo_reach) < 0
                            || (i as isize + hi_reach) as usize + 16 > src.len()
                            || i + 16 > dst.len()
                        {
                            // Tail near the buffer end: scalar.
                            for xx in x..w {
                                let ii = origin + y * stride + xx;
                                let v = src[ii] as i32;
                                let a = src[(ii as isize + na) as usize] as i32;
                                let b = src[(ii as isize + nb) as usize] as i32;
                                let e = (2 + (v - a).signum() + (v - b).signum()) as usize;
                                dst[ii] = (v + off[e] as i32).clamp(0, 255) as u8;
                            }
                            break;
                        }
                        let v = _mm_loadu_si128(src.as_ptr().add(i) as *const __m128i);
                        let a =
                            _mm_loadu_si128(src.as_ptr().offset(i as isize + na) as *const __m128i);
                        let b =
                            _mm_loadu_si128(src.as_ptr().offset(i as isize + nb) as *const __m128i);
                        // Unsigned compares: ge = (max(v, a) == v), gt = ge & !eq, lt = !ge.
                        let ge_a = _mm_cmpeq_epi8(_mm_max_epu8(v, a), v);
                        let gt_a = _mm_andnot_si128(_mm_cmpeq_epi8(v, a), ge_a);
                        let ge_b = _mm_cmpeq_epi8(_mm_max_epu8(v, b), v);
                        let gt_b = _mm_andnot_si128(_mm_cmpeq_epi8(v, b), ge_b);
                        // e = 2 + gt_a - lt_a + gt_b - lt_b with masks of -1: 2 - gt + lt.
                        let ones = _mm_cmpeq_epi8(v, v);
                        let lt_a = _mm_xor_si128(ge_a, ones);
                        let lt_b = _mm_xor_si128(ge_b, ones);
                        let e = _mm_add_epi8(
                            _mm_sub_epi8(_mm_sub_epi8(two, gt_a), gt_b),
                            _mm_add_epi8(lt_a, lt_b),
                        );
                        let o = edge_lut(&tab, e);
                        store_bytes16(dst.as_mut_ptr().add(i), add_offset_u8(v, o), n);
                        x += 16;
                    }
                }
            }
        }

        // ------------------------------------------------------------------
        // Deblocking — the shared i32-lane filters with byte loads and stores.
        // ------------------------------------------------------------------

        /// Eight consecutive bytes as two vectors of 4 x i32.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn ld8_u8(p: *const u8) -> (__m128i, __m128i) {
            unsafe {
                let v = _mm_loadl_epi64(p as *const __m128i);
                (zx8d(v), zx8dh(v))
            }
        }

        /// Two vectors of 4 x i32 (each within a byte) to eight bytes.
        #[target_feature(enable = $feat)]
        #[inline]
        unsafe fn pack8_u8(lo: __m128i, hi: __m128i) -> __m128i {
            unsafe {
                let p = pack8_u16(lo, hi);
                _mm_packus_epi16(p, p)
            }
        }

        #[allow(clippy::too_many_arguments)]
        fn deblock_luma_v_u8(
            data: &mut [u8],
            off: usize,
            stride: usize,
            beta: [i32; 2],
            tc: [i32; 2],
            no_p: [bool; 2],
            no_q: [bool; 2],
            max: i32,
        ) {
            if (beta[0] == 0 && tc[0] == 0) && (beta[1] == 0 && tc[1] == 0) {
                return;
            }
            assert!(off >= 4 && off + 7 * stride + 4 <= data.len());
            unsafe {
                deblock_luma_v_u8_impl(
                    data.as_mut_ptr().add(off),
                    stride,
                    beta,
                    tc,
                    no_p,
                    no_q,
                    max,
                )
            }
        }

        #[target_feature(enable = $feat)]
        #[allow(clippy::too_many_arguments)]
        unsafe fn deblock_luma_v_u8_impl(
            data: *mut u8,
            stride: usize,
            beta: [i32; 2],
            tc: [i32; 2],
            no_p: [bool; 2],
            no_q: [bool; 2],
            max: i32,
        ) {
            unsafe {
                let mut r = [_mm_setzero_si128(); 8];
                for i in 0..8 {
                    r[i] = zx8(_mm_loadl_epi64(
                        data.add(i * stride).sub(4) as *const __m128i
                    ));
                }
                transpose8_u16(&mut r);
                let mut v0 = [_mm_setzero_si128(); 8];
                let mut v1 = [_mm_setzero_si128(); 8];
                for k in 0..8 {
                    let (a, b) = widen_u16(r[k]);
                    v0[k] = a;
                    v1[k] = b;
                }
                luma_filter4(&mut v0, beta[0], tc[0], no_p[0], no_q[0], max);
                luma_filter4(&mut v1, beta[1], tc[1], no_p[1], no_q[1], max);
                for k in 0..8 {
                    r[k] = pack8_u16(v0[k], v1[k]);
                }
                transpose8_u16(&mut r);
                for i in 0..8 {
                    _mm_storel_epi64(
                        data.add(i * stride).sub(4) as *mut __m128i,
                        _mm_packus_epi16(r[i], r[i]),
                    );
                }
            }
        }

        #[allow(clippy::too_many_arguments)]
        fn deblock_luma_h_u8(
            data: &mut [u8],
            off: usize,
            stride: usize,
            beta: [i32; 2],
            tc: [i32; 2],
            no_p: [bool; 2],
            no_q: [bool; 2],
            max: i32,
        ) {
            if (beta[0] == 0 && tc[0] == 0) && (beta[1] == 0 && tc[1] == 0) {
                return;
            }
            assert!(off >= 4 * stride && off + 3 * stride + 8 <= data.len());
            unsafe {
                deblock_luma_h_u8_impl(
                    data.as_mut_ptr().add(off),
                    stride,
                    beta,
                    tc,
                    no_p,
                    no_q,
                    max,
                )
            }
        }

        #[target_feature(enable = $feat)]
        #[allow(clippy::too_many_arguments)]
        unsafe fn deblock_luma_h_u8_impl(
            data: *mut u8,
            stride: usize,
            beta: [i32; 2],
            tc: [i32; 2],
            no_p: [bool; 2],
            no_q: [bool; 2],
            max: i32,
        ) {
            unsafe {
                let mut v0 = [_mm_setzero_si128(); 8];
                let mut v1 = [_mm_setzero_si128(); 8];
                for k in 0..8 {
                    let (a, b) = ld8_u8(data.offset((k as isize - 4) * stride as isize));
                    v0[k] = a;
                    v1[k] = b;
                }
                luma_filter4(&mut v0, beta[0], tc[0], no_p[0], no_q[0], max);
                luma_filter4(&mut v1, beta[1], tc[1], no_p[1], no_q[1], max);
                for k in 1..7 {
                    _mm_storel_epi64(
                        data.offset((k as isize - 4) * stride as isize) as *mut __m128i,
                        pack8_u8(v0[k], v1[k]),
                    );
                }
            }
        }

        fn deblock_chroma_v_u8(
            data: &mut [u8],
            off: usize,
            stride: usize,
            tc: [i32; 4],
            no_p: [bool; 4],
            no_q: [bool; 4],
            max: i32,
        ) {
            if tc.iter().all(|&t| t == 0) {
                return;
            }
            assert!(off >= 2 && off + 7 * stride + 2 <= data.len());
            unsafe {
                deblock_chroma_v_u8_impl(data.as_mut_ptr().add(off), stride, tc, no_p, no_q, max)
            }
        }

        #[target_feature(enable = $feat)]
        unsafe fn deblock_chroma_v_u8_impl(
            data: *mut u8,
            stride: usize,
            tc: [i32; 4],
            no_p: [bool; 4],
            no_q: [bool; 4],
            max: i32,
        ) {
            unsafe {
                let mut r = [_mm_setzero_si128(); 8];
                for i in 0..8 {
                    let q = std::ptr::read_unaligned(data.add(i * stride).sub(2) as *const u32);
                    r[i] = zx8(_mm_cvtsi32_si128(q as i32));
                }
                let a0 = _mm_unpacklo_epi16(r[0], r[1]);
                let a1 = _mm_unpacklo_epi16(r[2], r[3]);
                let a2 = _mm_unpacklo_epi16(r[4], r[5]);
                let a3 = _mm_unpacklo_epi16(r[6], r[7]);
                let b0 = _mm_unpacklo_epi32(a0, a1); // p1 r0..3 | p0 r0..3
                let b1 = _mm_unpackhi_epi32(a0, a1); // q0 r0..3 | q1 r0..3
                let b2 = _mm_unpacklo_epi32(a2, a3); // rows 4..7
                let b3 = _mm_unpackhi_epi32(a2, a3);
                let col = |v: __m128i, hi: bool| if hi { zx16h(v) } else { zx16(v) };
                let mut v0 = [col(b0, false), col(b0, true), col(b1, false), col(b1, true)];
                let mut v1 = [col(b2, false), col(b2, true), col(b3, false), col(b3, true)];
                chroma_filter4(
                    &mut v0,
                    [tc[0], tc[1]],
                    [no_p[0], no_p[1]],
                    [no_q[0], no_q[1]],
                    max,
                );
                chroma_filter4(
                    &mut v1,
                    [tc[2], tc[3]],
                    [no_p[2], no_p[3]],
                    [no_q[2], no_q[3]],
                    max,
                );
                // (p0, q0) byte pairs per row.
                let p0 = pack8_u16(v0[1], v1[1]);
                let q0 = pack8_u16(v0[2], v1[2]);
                let pairs =
                    _mm_packus_epi16(_mm_unpacklo_epi16(p0, q0), _mm_unpackhi_epi16(p0, q0));
                let mut t = [0u16; 8];
                _mm_storeu_si128(t.as_mut_ptr() as *mut __m128i, pairs);
                for i in 0..8 {
                    std::ptr::write_unaligned(data.add(i * stride).sub(1) as *mut u16, t[i]);
                }
            }
        }

        fn deblock_chroma_h_u8(
            data: &mut [u8],
            off: usize,
            stride: usize,
            tc: [i32; 4],
            no_p: [bool; 4],
            no_q: [bool; 4],
            max: i32,
        ) {
            if tc.iter().all(|&t| t == 0) {
                return;
            }
            assert!(off >= 2 * stride && off + stride + 8 <= data.len());
            unsafe {
                deblock_chroma_h_u8_impl(data.as_mut_ptr().add(off), stride, tc, no_p, no_q, max)
            }
        }

        #[target_feature(enable = $feat)]
        unsafe fn deblock_chroma_h_u8_impl(
            data: *mut u8,
            stride: usize,
            tc: [i32; 4],
            no_p: [bool; 4],
            no_q: [bool; 4],
            max: i32,
        ) {
            unsafe {
                let (a0, a1) = ld8_u8(data.sub(2 * stride));
                let (b0, b1) = ld8_u8(data.sub(stride));
                let (c0, c1) = ld8_u8(data);
                let (d0, d1) = ld8_u8(data.add(stride));
                let mut v0 = [a0, b0, c0, d0];
                let mut v1 = [a1, b1, c1, d1];
                chroma_filter4(
                    &mut v0,
                    [tc[0], tc[1]],
                    [no_p[0], no_p[1]],
                    [no_q[0], no_q[1]],
                    max,
                );
                chroma_filter4(
                    &mut v1,
                    [tc[2], tc[3]],
                    [no_p[2], no_p[3]],
                    [no_q[2], no_q[3]],
                    max,
                );
                _mm_storel_epi64(data.sub(stride) as *mut __m128i, pack8_u8(v0[1], v1[1]));
                _mm_storel_epi64(data as *mut __m128i, pack8_u8(v0[2], v1[2]));
            }
        }
    };
}

// Each rung is a full compilation of the kernels, but the ladder calls only
// the install groups that rung improves, so the kernels it did not change
// are unreachable and are dropped. Nothing here is public: were these
// modules part of the crate's API, every rung would be retained in full.
// `dead_code` is allowed because "unused" is the intended state for most
// of three of the four rungs, not because anything is unreachable by
// mistake.

/// SSE2: baseline on x86-64, so this rung is the one that makes the scalar
/// kernels unreachable on this architecture.
pub(crate) mod sse2 {
    #![allow(dead_code)]
    kernels_u16!("sse2", sse2);
    kernels_u8!("sse2", sse2);
}

/// SSSE3: `pmaddubsw` for the byte interpolation filters, `pshufb` for the
/// SAO edge table, `pabsd` for the loop filters' lane-wise measures.
pub(crate) mod ssse3 {
    #![allow(dead_code)]
    kernels_u16!("ssse3", ssse3);
    kernels_u8!("ssse3", ssse3);
}

/// SSE4.1: `pblendvb` for lane selects, `pminsd` / `pmaxsd` for the loop
/// filters' clamps, `pmovzx` for the widening loads.
pub(crate) mod sse41 {
    #![allow(dead_code)]
    kernels_u16!("sse4.1", sse41);
    kernels_u8!("sse4.1", sse41);
}

/// AVX: the SSE4.1 algorithms, VEX-encoded.
pub(crate) mod avx {
    #![allow(dead_code)]
    kernels_u16!("avx", sse41);
    kernels_u8!("avx", sse41);
}

/// Install the best 16-bit-sample kernels `cpu` can run, one rung at a time.
pub fn install_u16(d: &mut HevcDsp<u16>, cpu: Cpu) {
    if cpu.sse2 {
        sse2::install_all_u16(d);
    }
    if cpu.ssse3 {
        ssse3::install_deblock_u16(d);
    }
    if cpu.sse41 {
        sse41::install_deblock_u16(d);
        sse41::install_sao_u16(d);
    }
    if cpu.avx {
        avx::install_all_u16(d);
    }
}

/// Install the best 8-bit-sample kernels `cpu` can run, one rung at a time.
///
/// Note what SSE4.1 does *not* re-install: the byte FIR is `pmaddubsw` from
/// SSSE3 up and SSE4.1 adds nothing it can use, so an SSE4.1 CPU keeps the
/// SSSE3 interpolation and takes SSE4.1 only where it is better.
pub fn install_u8(d: &mut HevcDsp<u8>, cpu: Cpu) {
    if cpu.sse2 {
        sse2::install_all_u8(d);
    }
    if cpu.ssse3 {
        ssse3::install_fir_u8(d);
        ssse3::install_fused_u8(d);
        ssse3::install_sao_edge_u8(d);
        ssse3::install_deblock_u8(d);
    }
    if cpu.sse41 {
        sse41::install_fused_u8(d);
        sse41::install_residual_u8(d);
        sse41::install_sao_band_u8(d);
        sse41::install_sao_edge_u8(d);
        sse41::install_deblock_u8(d);
    }
    if cpu.avx {
        avx::install_all_u8(d);
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use crate::dsp::hevc::MC_TMP_LEN;

    fn lcg(seed: &mut u64) -> u32 {
        *seed = seed
            .wrapping_mul(6364136223846793005)
            .wrapping_add(1442695040888963407);
        (*seed >> 33) as u32
    }

    /// Every rung the host can run, built the way `install_*` builds it in
    /// the field: cumulatively, so each table is exactly what a CPU of that
    /// generation would get.
    fn rungs() -> Vec<(&'static str, Cpu)> {
        let base = Cpu::SCALAR;
        [
            (
                "sse2",
                Cpu { sse2: true, ..base },
                std::is_x86_feature_detected!("sse2"),
            ),
            (
                "ssse3",
                Cpu {
                    sse2: true,
                    ssse3: true,
                    ..base
                },
                std::is_x86_feature_detected!("ssse3"),
            ),
            (
                "sse4.1",
                Cpu {
                    sse2: true,
                    ssse3: true,
                    sse41: true,
                    ..base
                },
                std::is_x86_feature_detected!("sse4.1"),
            ),
            (
                "avx",
                Cpu {
                    sse2: true,
                    ssse3: true,
                    sse41: true,
                    avx: true,
                    ..base
                },
                std::is_x86_feature_detected!("avx"),
            ),
        ]
        .into_iter()
        .filter(|&(_, _, have)| have)
        .map(|(n, c, _)| (n, c))
        .collect()
    }

    fn tables_u16() -> Vec<(&'static str, HevcDsp<u16>)> {
        rungs()
            .into_iter()
            .map(|(name, cpu)| {
                let mut d = HevcDsp::<u16>::SCALAR;
                install_u16(&mut d, cpu);
                (name, d)
            })
            .collect()
    }

    fn tables_u8() -> Vec<(&'static str, HevcDsp<u8>)> {
        rungs()
            .into_iter()
            .map(|(name, cpu)| {
                let mut d = HevcDsp::<u8>::SCALAR;
                install_u8(&mut d, cpu);
                (name, d)
            })
            .collect()
    }

    const SIZES: [(usize, usize); 9] = [
        (2, 4),
        (4, 4),
        (4, 8),
        (8, 4),
        (8, 8),
        (12, 16),
        (16, 16),
        (32, 8),
        (64, 16),
    ];

    #[test]
    fn interp_matches_scalar_u16() {
        let s = HevcDsp::<u16>::SCALAR;
        for (name, d) in tables_u16() {
            let mut seed = 3u64;
            let stride = 96;
            let src: Vec<u16> = (0..stride * 96)
                .map(|_| (lcg(&mut seed) % 1024) as u16)
                .collect();
            for &(w, h) in &SIZES {
                for frac in 0..4 {
                    let mut a = vec![0i16; w * h];
                    let mut b = vec![0i16; w * h];
                    (s.qpel_h)(&mut a, &src, stride, w, h, frac, 2);
                    (d.qpel_h)(&mut b, &src, stride, w, h, frac, 2);
                    assert_eq!(a, b, "{name} qpel_h {w}x{h} frac {frac}");
                    (s.qpel_v)(&mut a, &src, stride, w, h, frac, 2);
                    (d.qpel_v)(&mut b, &src, stride, w, h, frac, 2);
                    assert_eq!(a, b, "{name} qpel_v {w}x{h} frac {frac}");
                }
                for frac in 0..8 {
                    let mut a = vec![0i16; w * h];
                    let mut b = vec![0i16; w * h];
                    (s.epel_h)(&mut a, &src, stride, w, h, frac, 2);
                    (d.epel_h)(&mut b, &src, stride, w, h, frac, 2);
                    assert_eq!(a, b, "{name} epel_h {w}x{h} frac {frac}");
                    (s.epel_v)(&mut a, &src, stride, w, h, frac, 2);
                    (d.epel_v)(&mut b, &src, stride, w, h, frac, 2);
                    assert_eq!(a, b, "{name} epel_v {w}x{h} frac {frac}");
                }
                let mut a = vec![0i16; w * h];
                let mut b = vec![0i16; w * h];
                (s.qpel_copy)(&mut a, &src, stride, w, h, 2);
                (d.qpel_copy)(&mut b, &src, stride, w, h, 2);
                assert_eq!(a, b, "{name} copy {w}x{h}");
                // Second-stage vertical over 14-bit rows.
                let mid: Vec<i16> = (0..w * (h + 8))
                    .map(|_| (lcg(&mut seed) % 32768) as i16 - 16384)
                    .collect();
                for frac in 0..4 {
                    (s.qpel_v2)(&mut a, &mid, w, w, h, frac);
                    (d.qpel_v2)(&mut b, &mid, w, w, h, frac);
                    assert_eq!(a, b, "{name} qpel_v2 {w}x{h} frac {frac}");
                }
                for frac in 0..8 {
                    (s.epel_v2)(&mut a, &mid, w, w, h, frac);
                    (d.epel_v2)(&mut b, &mid, w, w, h, frac);
                    assert_eq!(a, b, "{name} epel_v2 {w}x{h} frac {frac}");
                }
            }
        }
    }

    /// The fused kernels at 16 bits, every rung the host has (AVX2 and
    /// AVX-512 tables included), at every depth they serve: samples uniform
    /// over the depth or on its rails, the other list's prediction over the
    /// 14-bit range a real one has, every block shape and fraction, both
    /// directions of the clip reached.
    #[test]
    fn fused_matches_scalar_u16() {
        let mut cpus = rungs();
        let top = Cpu::detect();
        if top.avx2 {
            cpus.push((
                "avx2",
                Cpu {
                    avx512: false,
                    avx512vnni: false,
                    ..top
                },
            ));
        }
        if top.avx512 {
            cpus.push(("avx512", top));
        }
        let s = HevcDsp::<u16>::SCALAR;
        let mut seed = 0xf05e_u64;
        let stride = 96;
        let mut ta = vec![0i16; MC_TMP_LEN];
        let mut tb = vec![0i16; MC_TMP_LEN];
        let mut n = 0;
        for (name, cpu) in cpus {
            let d = HevcDsp::<u16>::new(cpu);
            assert!(d.fused_mc, "{name}: no fused kernels at 16 bits");
            for bd in 8..=12u32 {
                let max = (1u32 << bd) - 1;
                for rails in [false, true] {
                    let src: Vec<u16> = (0..stride * 96)
                        .map(|_| {
                            if rails {
                                if lcg(&mut seed).is_multiple_of(2) {
                                    0
                                } else {
                                    max as u16
                                }
                            } else {
                                (lcg(&mut seed) % (max + 1)) as u16
                            }
                        })
                        .collect();
                    for &(w, h) in &SIZES {
                        // A prediction, within what an interpolation of this
                        // depth produces.
                        let other: Vec<i16> = (0..w * h)
                            .map(|_| (lcg(&mut seed) % 24000) as i16 - 2500)
                            .collect();
                        let ds = w + 9;
                        let mut a = vec![0u16; ds * h];
                        let mut b = vec![0u16; ds * h];
                        let what = |k: &str, fx: usize, fy: usize| {
                            format!("{name} {k} {w}x{h} ({fx},{fy}) {bd} bits rails {rails}")
                        };
                        for fx in 0..4 {
                            for fy in 0..4 {
                                (s.qpel_uni)(&mut a, ds, &src, stride, w, h, fx, fy, &mut ta, bd);
                                (d.qpel_uni)(&mut b, ds, &src, stride, w, h, fx, fy, &mut tb, bd);
                                assert_eq!(a, b, "{}", what("qpel_uni", fx, fy));
                                (s.qpel_bi)(
                                    &mut a, ds, &src, stride, w, h, fx, fy, &mut ta, &other, bd,
                                );
                                (d.qpel_bi)(
                                    &mut b, ds, &src, stride, w, h, fx, fy, &mut tb, &other, bd,
                                );
                                assert_eq!(a, b, "{}", what("qpel_bi", fx, fy));
                                n += 2;
                            }
                        }
                        for fx in 0..8 {
                            for fy in 0..8 {
                                (s.epel_uni)(&mut a, ds, &src, stride, w, h, fx, fy, &mut ta, bd);
                                (d.epel_uni)(&mut b, ds, &src, stride, w, h, fx, fy, &mut tb, bd);
                                assert_eq!(a, b, "{}", what("epel_uni", fx, fy));
                                (s.epel_bi)(
                                    &mut a, ds, &src, stride, w, h, fx, fy, &mut ta, &other, bd,
                                );
                                (d.epel_bi)(
                                    &mut b, ds, &src, stride, w, h, fx, fy, &mut tb, &other, bd,
                                );
                                assert_eq!(a, b, "{}", what("epel_bi", fx, fy));
                                n += 2;
                            }
                        }
                    }
                }
            }
        }
        assert!(n > 0);
    }

    #[test]
    fn combine_matches_scalar_u16() {
        let s = HevcDsp::<u16>::SCALAR;
        for (name, d) in tables_u16() {
            let mut seed = 7u64;
            for &(w, h) in &SIZES {
                let pa: Vec<i16> = (0..w * h)
                    .map(|_| (lcg(&mut seed) % 32768) as i16 - 16384)
                    .collect();
                let pb: Vec<i16> = (0..w * h)
                    .map(|_| (lcg(&mut seed) % 32768) as i16 - 16384)
                    .collect();
                let stride = w + 5;
                let mut a = vec![0u16; stride * h];
                let mut b = vec![0u16; stride * h];
                for &max in &[255i32, 1023, 4095] {
                    (s.uni)(&mut a, stride, &pa, w, h, 6, max);
                    (d.uni)(&mut b, stride, &pa, w, h, 6, max);
                    assert_eq!(a, b, "{name} uni {w}x{h} max {max}");
                    (s.bi)(&mut a, stride, &pa, &pb, w, h, 7, max);
                    (d.bi)(&mut b, stride, &pa, &pb, w, h, 7, max);
                    assert_eq!(a, b, "{name} bi {w}x{h} max {max}");
                    for &(lwd, wt, o) in
                        &[(6i32, 64i32, 0i32), (0, 1, 3), (5, -20, -7), (7, 127, 100)]
                    {
                        (s.weighted_uni)(&mut a, stride, &pa, w, h, lwd, wt, o, max);
                        (d.weighted_uni)(&mut b, stride, &pa, w, h, lwd, wt, o, max);
                        assert_eq!(a, b, "{name} wuni {w}x{h} {lwd} {wt} {o} max {max}");
                        (s.weighted_bi)(
                            &mut a,
                            stride,
                            &pa,
                            &pb,
                            w,
                            h,
                            lwd,
                            wt,
                            64 - wt,
                            o,
                            -o,
                            max,
                        );
                        (d.weighted_bi)(
                            &mut b,
                            stride,
                            &pa,
                            &pb,
                            w,
                            h,
                            lwd,
                            wt,
                            64 - wt,
                            o,
                            -o,
                            max,
                        );
                        assert_eq!(a, b, "{name} wbi {w}x{h} {lwd} {wt} {o} max {max}");
                    }
                }
            }
        }
    }

    /// The 4x4 inverse DCT and DST at every rung the host has, AVX2 and
    /// AVX-512 included (they take this module's kernels at 4x4), in both
    /// tables: coefficients across the whole of i16, so both stages' clips
    /// are reached, dense and within a random bounding box, at the shifts of
    /// 8, 10 and 12 bits.
    #[test]
    fn transforms4_match_scalar_at_every_rung() {
        let mut cpus = rungs();
        let top = Cpu::detect();
        if top.avx2 {
            cpus.push((
                "avx2",
                Cpu {
                    avx512: false,
                    avx512vnni: false,
                    ..top
                },
            ));
        }
        if top.avx512 {
            cpus.push(("avx512", top));
        }
        let s = HevcDsp::<u16>::SCALAR;
        let mut seed = 0x4d57_u64;
        let mut n = 0;
        for (name, cpu) in cpus {
            let d16 = HevcDsp::<u16>::new(cpu);
            let d8 = HevcDsp::<u8>::new(cpu);
            for trial in 0..3000 {
                let (mx, my) = if trial % 3 == 0 {
                    (3, 3)
                } else {
                    ((lcg(&mut seed) % 4) as usize, (lcg(&mut seed) % 4) as usize)
                };
                let mut c = [0i16; 16];
                for y in 0..=my {
                    for x in 0..=mx {
                        c[y * 4 + x] = match lcg(&mut seed) % 6 {
                            0 => 32767,
                            1 => -32768,
                            2 => 0,
                            _ => lcg(&mut seed) as i16,
                        };
                    }
                }
                let bd_shift = 12 - (trial % 3) * 2;
                let mut want = c;
                (s.idct[0])(&mut want, bd_shift, mx, my);
                let mut want_dst = c;
                (s.idst4)(&mut want_dst, bd_shift, 3, 3);
                for (table, idct, idst) in [
                    ("u16", d16.idct[0], d16.idst4),
                    ("u8", d8.idct[0], d8.idst4),
                ] {
                    let mut got = c;
                    idct(&mut got, bd_shift, mx, my);
                    assert_eq!(
                        got, want,
                        "{name} {table} idct4 trial {trial} max {mx},{my} shift {bd_shift} {c:?}"
                    );
                    let mut got = c;
                    idst(&mut got, bd_shift, 3, 3);
                    assert_eq!(
                        got, want_dst,
                        "{name} {table} idst4 trial {trial} shift {bd_shift} {c:?}"
                    );
                    n += 2;
                }
            }
        }
        assert!(n > 0);
    }

    /// ns per call of the 4x4 inverse DCT and DST, scalar against every
    /// rung (AVX2 and AVX-512 take the AVX kernel), median of seven paired
    /// rounds; the two scalar rows are the same-table control. `cargo test
    /// --release --lib hevc_x86_128 -- --ignored --nocapture`.
    #[test]
    #[ignore]
    fn transforms4_bench() {
        use std::time::Instant;
        let mut seed = 0xb4d7_u64;
        let blocks: Vec<[i16; 16]> = (0..64)
            .map(|_| std::array::from_fn(|_| (lcg(&mut seed) % 2001) as i16 - 1000))
            .collect();
        let s = HevcDsp::<u16>::SCALAR;
        let mut tabs = vec![("scalar", s), ("scalar-again", s)];
        tabs.extend(tables_u16());
        const ROUNDS: usize = 7;
        const PER: usize = 200_000;
        let median = |mut v: Vec<f64>| {
            v.sort_by(|a, b| a.total_cmp(b));
            v[v.len() / 2]
        };
        for (label, dst) in [("idct4", false), ("idst4", true)] {
            // `ns[round][table]`: every table back to back within a round.
            let mut ns = vec![vec![0f64; tabs.len()]; ROUNDS];
            let mut sink = 0i64;
            for round in ns.iter_mut() {
                for (slot, (_, d)) in round.iter_mut().zip(&tabs) {
                    let f = if dst { d.idst4 } else { d.idct[0] };
                    let start = Instant::now();
                    for i in 0..PER {
                        let mut c = blocks[i & 63];
                        f(std::hint::black_box(&mut c), 12, 3, 3);
                        sink = sink.wrapping_add(c[5] as i64);
                    }
                    *slot = start.elapsed().as_nanos() as f64 / PER as f64;
                }
            }
            for (t, (name, _)) in tabs.iter().enumerate() {
                let own = median(ns.iter().map(|r| r[t]).collect());
                let ratio = median(ns.iter().map(|r| r[0] / r[t]).collect());
                println!(
                    "{label} {name:13} {own:7.1} ns/call  {ratio:5.2}x scalar [{}]",
                    sink & 1
                );
            }
        }
    }

    #[test]
    fn idct_matches_scalar_u16() {
        let s = HevcDsp::<u16>::SCALAR;
        for (name, d) in tables_u16() {
            let mut seed = 13u64;
            for (li, &n) in [4usize, 8, 16, 32].iter().enumerate() {
                for trial in 0..40 {
                    let max_x = (lcg(&mut seed) as usize) % n;
                    let max_y = (lcg(&mut seed) as usize) % n;
                    let mut a = vec![0i16; n * n];
                    for y in 0..=max_y {
                        for x in 0..=max_x {
                            a[y * n + x] = (lcg(&mut seed) % 2048) as i16 - 1024;
                        }
                    }
                    let mut b = a.clone();
                    let bd_shift = 20 - 8;
                    (s.idct[li])(&mut a, bd_shift, max_x, max_y);
                    (d.idct[li])(&mut b, bd_shift, max_x, max_y);
                    assert_eq!(a, b, "{name} idct{n} trial {trial} max {max_x},{max_y}");
                }
            }
            // Residual add.
            let mut seed = 29u64;
            for &n in &[4usize, 8, 16, 32] {
                let stride = n + 7;
                let base: Vec<u16> = (0..stride * n)
                    .map(|_| (lcg(&mut seed) % 1024) as u16)
                    .collect();
                let res: Vec<i16> = (0..n * n)
                    .map(|_| (lcg(&mut seed) % 2048) as i16 - 1024)
                    .collect();
                let mut a = base.clone();
                let mut b = base.clone();
                (s.add_residual)(&mut a, stride, &res, n, 1023);
                (d.add_residual)(&mut b, stride, &res, n, 1023);
                assert_eq!(a, b, "{name} add_residual {n}");
            }
        }
    }

    #[test]
    fn sao_matches_scalar_u16() {
        let s = HevcDsp::<u16>::SCALAR;
        for (name, d) in tables_u16() {
            let mut seed = 19u64;
            let stride = 72;
            let src: Vec<u16> = (0..stride * 40)
                .map(|_| (lcg(&mut seed) % 1024) as u16)
                .collect();
            for &(w, h) in &SIZES {
                let mut table = [0i16; 32];
                let start = (lcg(&mut seed) % 28) as usize;
                for k in 0..4 {
                    table[start + k] = (lcg(&mut seed) % 15) as i16 - 7;
                }
                let mut a = vec![0u16; src.len()];
                let mut b = vec![0u16; src.len()];
                (s.sao_band)(&mut a, stride, &src, stride, w, h, &table, 5, 1023);
                (d.sao_band)(&mut b, stride, &src, stride, w, h, &table, 5, 1023);
                assert_eq!(a, b, "{name} sao_band {w}x{h}");
                let mut off = [0i16; 5];
                for k in [0usize, 1, 3, 4] {
                    off[k] = (lcg(&mut seed) % 15) as i16 - 7;
                }
                for &(na, nb) in &[
                    (-1isize, 1isize),
                    (-(stride as isize), stride as isize),
                    (-(stride as isize) - 1, stride as isize + 1),
                ] {
                    let origin = 4 * stride + 4;
                    let mut a = src.clone();
                    let mut b = src.clone();
                    (s.sao_edge)(&mut a, &src, origin, stride, w, h, na, nb, &off, 1023);
                    (d.sao_edge)(&mut b, &src, origin, stride, w, h, na, nb, &off, 1023);
                    assert_eq!(a, b, "{name} sao_edge {w}x{h} {na},{nb}");
                }
            }
        }
    }

    #[test]
    fn deblocking_matches_scalar_u16() {
        let s = HevcDsp::<u16>::SCALAR;
        for (name, d) in tables_u16() {
            let mut seed = 23u64;
            let stride = 48;
            for trial in 0..500 {
                let base = lcg(&mut seed) % 1024;
                let spread = 1 + lcg(&mut seed) % 96;
                let plane: Vec<u16> = (0..stride * 32)
                    .map(|_| ((base + lcg(&mut seed) % spread).min(1023)) as u16)
                    .collect();
                let beta = [(lcg(&mut seed) % 64) as i32, (lcg(&mut seed) % 64) as i32];
                let tc = [(lcg(&mut seed) % 20) as i32, (lcg(&mut seed) % 20) as i32];
                let bl = |v: u32| v.is_multiple_of(2);
                let no_p = [bl(lcg(&mut seed)), bl(lcg(&mut seed))];
                let no_q = [bl(lcg(&mut seed)), bl(lcg(&mut seed))];
                let tc4 = [
                    tc[0],
                    tc[1],
                    (lcg(&mut seed) % 20) as i32,
                    (lcg(&mut seed) % 20) as i32,
                ];
                let np4 = [no_p[0], no_p[1], bl(lcg(&mut seed)), bl(lcg(&mut seed))];
                let nq4 = [no_q[0], no_q[1], bl(lcg(&mut seed)), bl(lcg(&mut seed))];
                let off = 8 * stride + 8;
                let mut a = plane.clone();
                let mut b = plane.clone();
                match trial % 4 {
                    0 => {
                        (s.deblock_luma_v)(&mut a, off, stride, beta, tc, no_p, no_q, 1023);
                        (d.deblock_luma_v)(&mut b, off, stride, beta, tc, no_p, no_q, 1023);
                    }
                    1 => {
                        (s.deblock_luma_h)(&mut a, off, stride, beta, tc, no_p, no_q, 1023);
                        (d.deblock_luma_h)(&mut b, off, stride, beta, tc, no_p, no_q, 1023);
                    }
                    2 => {
                        (s.deblock_chroma_v)(&mut a, off, stride, tc4, np4, nq4, 1023);
                        (d.deblock_chroma_v)(&mut b, off, stride, tc4, np4, nq4, 1023);
                    }
                    _ => {
                        (s.deblock_chroma_h)(&mut a, off, stride, tc4, np4, nq4, 1023);
                        (d.deblock_chroma_h)(&mut b, off, stride, tc4, np4, nq4, 1023);
                    }
                }
                assert_eq!(a, b, "{name} deblock kind {} trial {trial}", trial % 4);
            }
        }
    }

    #[test]
    fn interp_matches_scalar_u8() {
        let s = HevcDsp::<u8>::SCALAR;
        for (name, d) in tables_u8() {
            let mut seed = 31u64;
            let stride = 96;
            let src: Vec<u8> = (0..stride * 96).map(|_| lcg(&mut seed) as u8).collect();
            for &(w, h) in &SIZES {
                let mut a = vec![0i16; w * h];
                let mut b = vec![0i16; w * h];
                for frac in 0..4 {
                    (s.qpel_h)(&mut a, &src, stride, w, h, frac, 0);
                    (d.qpel_h)(&mut b, &src, stride, w, h, frac, 0);
                    assert_eq!(a, b, "{name} qpel_h u8 {w}x{h} frac {frac}");
                    (s.qpel_v)(&mut a, &src, stride, w, h, frac, 0);
                    (d.qpel_v)(&mut b, &src, stride, w, h, frac, 0);
                    assert_eq!(a, b, "{name} qpel_v u8 {w}x{h} frac {frac}");
                }
                for frac in 0..8 {
                    (s.epel_h)(&mut a, &src, stride, w, h, frac, 0);
                    (d.epel_h)(&mut b, &src, stride, w, h, frac, 0);
                    assert_eq!(a, b, "{name} epel_h u8 {w}x{h} frac {frac}");
                    (s.epel_v)(&mut a, &src, stride, w, h, frac, 0);
                    (d.epel_v)(&mut b, &src, stride, w, h, frac, 0);
                    assert_eq!(a, b, "{name} epel_v u8 {w}x{h} frac {frac}");
                }
                (s.qpel_copy)(&mut a, &src, stride, w, h, 6);
                (d.qpel_copy)(&mut b, &src, stride, w, h, 6);
                assert_eq!(a, b, "{name} copy u8 {w}x{h}");
            }
        }
    }

    #[test]
    fn fused_matches_scalar_u8() {
        let s = HevcDsp::<u8>::SCALAR;
        for (name, d) in tables_u8() {
            let mut seed = 37u64;
            let stride = 128;
            let src: Vec<u8> = (0..stride * 128).map(|_| lcg(&mut seed) as u8).collect();
            let mut ta = vec![0i16; MC_TMP_LEN];
            let mut tb = vec![0i16; MC_TMP_LEN];
            for &(w, h) in &SIZES {
                let other: Vec<i16> = (0..w * h)
                    .map(|_| (lcg(&mut seed) % 32768) as i16 - 16384)
                    .collect();
                let ds = w + 9;
                let mut a = vec![0u8; ds * h];
                let mut b = vec![0u8; ds * h];
                for fx in 0..4 {
                    for fy in 0..4 {
                        (s.qpel_uni)(&mut a, ds, &src, stride, w, h, fx, fy, &mut ta, 8);
                        (d.qpel_uni)(&mut b, ds, &src, stride, w, h, fx, fy, &mut tb, 8);
                        assert_eq!(a, b, "{name} qpel_uni {w}x{h} {fx},{fy}");
                        (s.qpel_bi)(&mut a, ds, &src, stride, w, h, fx, fy, &mut ta, &other, 8);
                        (d.qpel_bi)(&mut b, ds, &src, stride, w, h, fx, fy, &mut tb, &other, 8);
                        assert_eq!(a, b, "{name} qpel_bi {w}x{h} {fx},{fy}");
                    }
                }
                for fx in 0..8 {
                    for fy in 0..8 {
                        (s.epel_uni)(&mut a, ds, &src, stride, w, h, fx, fy, &mut ta, 8);
                        (d.epel_uni)(&mut b, ds, &src, stride, w, h, fx, fy, &mut tb, 8);
                        assert_eq!(a, b, "{name} epel_uni {w}x{h} {fx},{fy}");
                        (s.epel_bi)(&mut a, ds, &src, stride, w, h, fx, fy, &mut ta, &other, 8);
                        (d.epel_bi)(&mut b, ds, &src, stride, w, h, fx, fy, &mut tb, &other, 8);
                        assert_eq!(a, b, "{name} epel_bi {w}x{h} {fx},{fy}");
                    }
                }
            }
        }
    }

    #[test]
    fn combine_matches_scalar_u8() {
        let s = HevcDsp::<u8>::SCALAR;
        for (name, d) in tables_u8() {
            let mut seed = 41u64;
            for &(w, h) in &SIZES {
                let pa: Vec<i16> = (0..w * h)
                    .map(|_| (lcg(&mut seed) % 32768) as i16 - 16384)
                    .collect();
                let pb: Vec<i16> = (0..w * h)
                    .map(|_| (lcg(&mut seed) % 32768) as i16 - 16384)
                    .collect();
                let stride = w + 5;
                let mut a = vec![0u8; stride * h];
                let mut b = vec![0u8; stride * h];
                (s.uni)(&mut a, stride, &pa, w, h, 6, 255);
                (d.uni)(&mut b, stride, &pa, w, h, 6, 255);
                assert_eq!(a, b, "{name} uni u8 {w}x{h}");
                (s.bi)(&mut a, stride, &pa, &pb, w, h, 7, 255);
                (d.bi)(&mut b, stride, &pa, &pb, w, h, 7, 255);
                assert_eq!(a, b, "{name} bi u8 {w}x{h}");
                for &(lwd, wt, o) in &[(6i32, 64i32, 0i32), (0, 1, 3), (5, -20, -7), (7, 127, 100)]
                {
                    (s.weighted_uni)(&mut a, stride, &pa, w, h, lwd, wt, o, 255);
                    (d.weighted_uni)(&mut b, stride, &pa, w, h, lwd, wt, o, 255);
                    assert_eq!(a, b, "{name} wuni u8 {w}x{h} {lwd} {wt} {o}");
                    (s.weighted_bi)(&mut a, stride, &pa, &pb, w, h, lwd, wt, 64 - wt, o, -o, 255);
                    (d.weighted_bi)(&mut b, stride, &pa, &pb, w, h, lwd, wt, 64 - wt, o, -o, 255);
                    assert_eq!(a, b, "{name} wbi u8 {w}x{h} {lwd} {wt} {o}");
                }
            }
            // Residual add.
            let mut seed = 43u64;
            for &n in &[4usize, 8, 16, 32] {
                let stride = n + 7;
                let base: Vec<u8> = (0..stride * n).map(|_| lcg(&mut seed) as u8).collect();
                let res: Vec<i16> = (0..n * n)
                    .map(|_| (lcg(&mut seed) % 512) as i16 - 256)
                    .collect();
                let mut a = base.clone();
                let mut b = base.clone();
                (s.add_residual)(&mut a, stride, &res, n, 255);
                (d.add_residual)(&mut b, stride, &res, n, 255);
                assert_eq!(a, b, "{name} add_residual u8 {n}");
            }
        }
    }

    #[test]
    fn sao_matches_scalar_u8() {
        let s = HevcDsp::<u8>::SCALAR;
        for (name, d) in tables_u8() {
            let mut seed = 47u64;
            let stride = 72;
            let src: Vec<u8> = (0..stride * 40).map(|_| lcg(&mut seed) as u8).collect();
            for &(w, h) in &SIZES {
                let mut table = [0i16; 32];
                let start = (lcg(&mut seed) % 28) as usize;
                for k in 0..4 {
                    table[start + k] = (lcg(&mut seed) % 15) as i16 - 7;
                }
                let mut a = vec![0u8; src.len()];
                let mut b = vec![0u8; src.len()];
                (s.sao_band)(&mut a, stride, &src, stride, w, h, &table, 3, 255);
                (d.sao_band)(&mut b, stride, &src, stride, w, h, &table, 3, 255);
                assert_eq!(a, b, "{name} sao_band u8 {w}x{h}");
                let mut off = [0i16; 5];
                for k in [0usize, 1, 3, 4] {
                    off[k] = (lcg(&mut seed) % 15) as i16 - 7;
                }
                for &(na, nb) in &[
                    (-1isize, 1isize),
                    (-(stride as isize), stride as isize),
                    (-(stride as isize) - 1, stride as isize + 1),
                ] {
                    let origin = 4 * stride + 4;
                    let mut a = src.clone();
                    let mut b = src.clone();
                    (s.sao_edge)(&mut a, &src, origin, stride, w, h, na, nb, &off, 255);
                    (d.sao_edge)(&mut b, &src, origin, stride, w, h, na, nb, &off, 255);
                    assert_eq!(a, b, "{name} sao_edge u8 {w}x{h} {na},{nb}");
                }
            }
        }
    }

    #[test]
    fn deblocking_matches_scalar_u8() {
        let s = HevcDsp::<u8>::SCALAR;
        for (name, d) in tables_u8() {
            let mut seed = 53u64;
            let stride = 48;
            for trial in 0..500 {
                let base = lcg(&mut seed) % 256;
                let spread = 1 + lcg(&mut seed) % 48;
                let plane: Vec<u8> = (0..stride * 32)
                    .map(|_| ((base + lcg(&mut seed) % spread).min(255)) as u8)
                    .collect();
                let beta = [(lcg(&mut seed) % 64) as i32, (lcg(&mut seed) % 64) as i32];
                let tc = [(lcg(&mut seed) % 20) as i32, (lcg(&mut seed) % 20) as i32];
                let bl = |v: u32| v.is_multiple_of(2);
                let no_p = [bl(lcg(&mut seed)), bl(lcg(&mut seed))];
                let no_q = [bl(lcg(&mut seed)), bl(lcg(&mut seed))];
                let tc4 = [
                    tc[0],
                    tc[1],
                    (lcg(&mut seed) % 20) as i32,
                    (lcg(&mut seed) % 20) as i32,
                ];
                let np4 = [no_p[0], no_p[1], bl(lcg(&mut seed)), bl(lcg(&mut seed))];
                let nq4 = [no_q[0], no_q[1], bl(lcg(&mut seed)), bl(lcg(&mut seed))];
                let off = 8 * stride + 8;
                let mut a = plane.clone();
                let mut b = plane.clone();
                match trial % 4 {
                    0 => {
                        (s.deblock_luma_v)(&mut a, off, stride, beta, tc, no_p, no_q, 255);
                        (d.deblock_luma_v)(&mut b, off, stride, beta, tc, no_p, no_q, 255);
                    }
                    1 => {
                        (s.deblock_luma_h)(&mut a, off, stride, beta, tc, no_p, no_q, 255);
                        (d.deblock_luma_h)(&mut b, off, stride, beta, tc, no_p, no_q, 255);
                    }
                    2 => {
                        (s.deblock_chroma_v)(&mut a, off, stride, tc4, np4, nq4, 255);
                        (d.deblock_chroma_v)(&mut b, off, stride, tc4, np4, nq4, 255);
                    }
                    _ => {
                        (s.deblock_chroma_h)(&mut a, off, stride, tc4, np4, nq4, 255);
                        (d.deblock_chroma_h)(&mut b, off, stride, tc4, np4, nq4, 255);
                    }
                }
                assert_eq!(a, b, "{name} deblock u8 kind {} trial {trial}", trial % 4);
            }
        }
    }
}
