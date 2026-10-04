//! H.265 kernels: inverse transforms, residual add, interpolation filters,
//! sample combination / weighting, SAO. Every kernel has a scalar reference
//! here; [`HevcDsp::new`] swaps in the SIMD versions from
//! `super::hevc_avx2` (x86-64) / `super::hevc_neon` (AArch64) /
//! `super::hevc_wasm128` (wasm32) when the CPU has them.
//!
//! Sample planes are `u16` at any bit depth; interpolation intermediates are
//! `i16` at 14-bit precision (8.5.3.3.3), coefficients and residuals `i16`
//! (the standard clips them to 16 bits, 8.6.2 / 8.6.4.2). Above 12 bits,
//! and under `extended_precision_processing_flag`, none of that holds: the
//! `*_wide` kernels at the end take `i32` and accumulate in `i64`, scalar
//! only — nothing in the table is touched for them.

use super::Cpu;
use crate::hevc::frame::Sample;
use crate::hevc::tables::{EPEL_FILTERS, QPEL_FILTERS, TRANSFORM32};

/// Inverse DCT of an `n x n` block in place: `coeffs` (raster, scaled
/// coefficients) becomes residual samples. `bd_shift` = 20 − BitDepth;
/// `max_x` / `max_y` bound the nonzero coefficients (inclusive).
pub type IdctFn = fn(coeffs: &mut [i16], bd_shift: i32, max_x: usize, max_y: usize);
/// Add a residual block to `dst` with clipping to `0..=max`.
pub type AddResidualFn<S> = fn(dst: &mut [S], stride: usize, res: &[i16], n: usize, max: i32);
/// Interpolate a `w x h` block. `src` points at the first tap of the first
/// output sample (3 samples / rows before the block for luma, 1 for chroma),
/// `frac` is the sub-sample phase (1..=3 luma, 1..=7 chroma), `shift` the
/// normalisation shift (shift1 = Min(4, BitDepth − 8)).
pub type InterpFn<S> =
    fn(dst: &mut [i16], src: &[S], src_stride: usize, w: usize, h: usize, frac: usize, shift: i32);
/// Copy with `<< shift` into the 14-bit domain.
pub type CopyFn<S> =
    fn(dst: &mut [i16], src: &[S], src_stride: usize, w: usize, h: usize, shift: i32);
/// Uni-prediction: `dst = clip((src + round) >> shift)`.
pub type UniFn<S> =
    fn(dst: &mut [S], stride: usize, src: &[i16], w: usize, h: usize, shift: i32, max: i32);
/// Bi-prediction: `dst = clip((a + b + round) >> shift)`.
pub type BiFn<S> = fn(
    dst: &mut [S],
    stride: usize,
    a: &[i16],
    b: &[i16],
    w: usize,
    h: usize,
    shift: i32,
    max: i32,
);
/// Weighted uni-prediction: `dst = clip(((src * w + round) >> log2wd) + o)`.
pub type WeightedUniFn<S> = fn(
    dst: &mut [S],
    stride: usize,
    src: &[i16],
    w: usize,
    h: usize,
    log2_wd: i32,
    wt: i32,
    o: i32,
    max: i32,
);
/// Weighted bi-prediction: `dst = clip((a * w0 + b * w1 + ((o0 + o1 + 1) << log2wd)) >> (log2wd + 1))`.
pub type WeightedBiFn<S> = fn(
    dst: &mut [S],
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
);
/// SAO band offset over a `w x h` region: `dst[i] = clip(src[i] + table[src[i] >> shift])`.
pub type SaoBandFn<S> = fn(
    dst: &mut [S],
    dst_stride: usize,
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    table: &[i16; 32],
    shift: i32,
    max: i32,
);
/// SAO edge offset over a `w x h` region at index `origin` of `dst` and `src`
/// (same geometry, `stride`), whose two neighbours at offsets `na` / `nb`
/// (in samples, relative to the sample) are all inside the picture and
/// usable: `dst = clip(src + off[2 + sign(src - a) + sign(src - b)])` with
/// `off` indexed by the raw edgeIdx (0..=4, index 2 = 0).
pub type SaoEdgeFn<S> = fn(
    dst: &mut [S],
    src: &[S],
    origin: usize,
    stride: usize,
    w: usize,
    h: usize,
    na: isize,
    nb: isize,
    off: &[i16; 5],
    max: i32,
);

/// Fused uni-prediction: interpolate a `w x h` block at fractional position
/// `(fx, fy)` and write the default-weighted samples straight into `dst`
/// (stride `dst_stride`). `src` starts at the filter window's origin — the
/// block's top-left minus 3 (luma) or 1 (chroma) samples in each direction
/// — with stride `src_stride`. `tmp` is scratch of at least
/// [`super::hevc::MC_TMP_LEN`] entries.
pub type UniInterpFn<S> = fn(
    dst: &mut [S],
    dst_stride: usize,
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    fx: usize,
    fy: usize,
    tmp: &mut [i16],
    bit_depth: u32,
);
/// Fused bi-prediction: as [`UniInterpFn`], averaged with `other`, the
/// other list's 14-bit prediction (`w * h`, stride `w`).
pub type BiInterpFn<S> = fn(
    dst: &mut [S],
    dst_stride: usize,
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    fx: usize,
    fy: usize,
    tmp: &mut [i16],
    other: &[i16],
    bit_depth: u32,
);

/// Planar intra prediction (8.4.4.2.5) of an `n x n` block at the start of
/// `dst` (stride `stride`) from its reference samples `left[0..=n]`
/// (`p[-1][y]`) and `top[0..=n]` (`p[x][-1]`), after substitution and any
/// smoothing.
pub type IntraPlanarFn<S> = fn(dst: &mut [S], stride: usize, left: &[u16], top: &[u16], n: usize);
/// DC intra prediction (8.4.4.2.5) from `left[0..n]` and `top[0..n]`, with
/// the edge filter of the first row and column when `edge` (luma, `n < 32`,
/// the boundary filter enabled).
pub type IntraDcFn<S> =
    fn(dst: &mut [S], stride: usize, left: &[u16], top: &[u16], n: usize, edge: bool);
/// Angular intra prediction (8.4.4.2.6): with `iIdx = ((y + 1) * angle) >>
/// 5` and `iFact = ((y + 1) * angle) & 31`, sample `(x, y)` is `((32 -
/// iFact) * ref[x + iIdx + 1] + iFact * ref[x + iIdx + 2] + 16) >> 5`, or
/// `ref[x + iIdx + 1]` when `iFact` is 0; `refs[n + k]` holds `ref[k]` for
/// `k` in `-n..=2n` and may run on past `3n + 1` (a SIMD kernel may read
/// there, and must not use what it reads). `transposed` stores sample `(x,
/// y)` at `(y, x)`: the horizontal modes 2..=17, which predict along
/// columns.
pub type IntraAngularFn<S> =
    fn(dst: &mut [S], stride: usize, refs: &[u16], n: usize, angle: i32, transposed: bool);

/// Scratch the fused interpolation kernels need: the horizontal stage of a
/// 64x64 block over `64 + 7` rows, plus a 64x64 14-bit prediction.
pub const MC_TMP_LEN: usize = 64 * (64 + 7) + 64 * 64;

/// The kernel table.
#[derive(Clone, Copy)]
pub struct HevcDsp<S: Sample = u16> {
    /// Which CPU features the table was built for.
    pub cpu: Cpu,
    /// Inverse DCT by `log2 - 2`.
    pub idct: [IdctFn; 4],
    /// Inverse DST 4x4 (intra luma 4x4).
    pub idst4: IdctFn,
    /// Residual add.
    pub add_residual: AddResidualFn<S>,
    /// Luma copy / horizontal / vertical 8-tap.
    pub qpel_copy: CopyFn<S>,
    /// See `qpel_copy`.
    pub qpel_h: InterpFn<S>,
    /// See `qpel_copy`.
    pub qpel_v: InterpFn<S>,
    /// Vertical 8-tap over 14-bit intermediates (second stage of hv).
    pub qpel_v2:
        fn(dst: &mut [i16], src: &[i16], src_stride: usize, w: usize, h: usize, frac: usize),
    /// Chroma copy / horizontal / vertical 4-tap.
    pub epel_copy: CopyFn<S>,
    /// See `epel_copy`.
    pub epel_h: InterpFn<S>,
    /// See `epel_copy`.
    pub epel_v: InterpFn<S>,
    /// Vertical 4-tap over 14-bit intermediates.
    pub epel_v2:
        fn(dst: &mut [i16], src: &[i16], src_stride: usize, w: usize, h: usize, frac: usize),
    /// Sample combination.
    pub uni: UniFn<S>,
    /// See `uni`.
    pub bi: BiFn<S>,
    /// See `uni`.
    pub weighted_uni: WeightedUniFn<S>,
    /// See `uni`.
    pub weighted_bi: WeightedBiFn<S>,
    /// Fused luma interpolation + default uni-prediction.
    pub qpel_uni: UniInterpFn<S>,
    /// Fused chroma interpolation + default uni-prediction.
    pub epel_uni: UniInterpFn<S>,
    /// Fused luma interpolation + default bi-prediction.
    pub qpel_bi: BiInterpFn<S>,
    /// Fused chroma interpolation + default bi-prediction.
    pub epel_bi: BiInterpFn<S>,
    /// Whether the fused entries are real kernels (worth calling) rather
    /// than the scalar composition of the two-pass ones.
    pub fused_mc: bool,
    /// SAO.
    pub sao_band: SaoBandFn<S>,
    /// See `sao_band`.
    pub sao_edge: SaoEdgeFn<S>,
    /// Deblocking: two 4-line luma segments of a vertical edge.
    pub deblock_luma_v: LumaDeblockFn<S>,
    /// Deblocking: two 4-line luma segments of a horizontal edge.
    pub deblock_luma_h: LumaDeblockFn<S>,
    /// Deblocking: four 2-line chroma segments of a vertical edge.
    pub deblock_chroma_v: ChromaDeblockFn<S>,
    /// Deblocking: four 2-line chroma segments of a horizontal edge.
    pub deblock_chroma_h: ChromaDeblockFn<S>,
    /// Intra prediction: planar.
    pub intra_planar: IntraPlanarFn<S>,
    /// Intra prediction: DC.
    pub intra_dc: IntraDcFn<S>,
    /// Intra prediction: the angular modes.
    pub intra_angular: IntraAngularFn<S>,
}

/// Deblock eight lines of a luma edge — two 4-line segments with their own
/// `beta`, `tc` and p/q exemptions (8.7.2.5.3–7); a segment with `tc == 0`
/// and `beta == 0` is left alone. `off` is the offset of q0 on the first
/// line; a vertical edge (`_v`) has its lines `stride` apart and p/q
/// samples 1 apart, a horizontal edge (`_h`) the other way round.
pub type LumaDeblockFn<S> = fn(
    data: &mut [S],
    off: usize,
    stride: usize,
    beta: [i32; 2],
    tc: [i32; 2],
    no_p: [bool; 2],
    no_q: [bool; 2],
    max: i32,
);
/// Deblock eight lines of a 4:2:0 chroma edge — four 2-line segments with
/// their own `tc` (0 = leave alone) and exemptions (8.7.2.5.5).
pub type ChromaDeblockFn<S> = fn(
    data: &mut [S],
    off: usize,
    stride: usize,
    tc: [i32; 4],
    no_p: [bool; 4],
    no_q: [bool; 4],
    max: i32,
);

impl<S: Sample> HevcDsp<S> {
    /// The scalar reference table.
    pub fn scalar() -> Self {
        HevcDsp {
            cpu: Cpu::SCALAR,
            idct: [
                idct_scalar::<4>,
                idct_scalar::<8>,
                idct_scalar::<16>,
                idct_scalar::<32>,
            ],
            idst4: idst4_scalar,
            add_residual: add_residual_scalar::<S>,
            qpel_copy: copy_scalar::<S>,
            qpel_h: qpel_h_scalar::<S>,
            qpel_v: qpel_v_scalar::<S>,
            qpel_v2: qpel_v2_scalar,
            epel_copy: copy_scalar::<S>,
            epel_h: epel_h_scalar::<S>,
            epel_v: epel_v_scalar::<S>,
            epel_v2: epel_v2_scalar,
            uni: uni_scalar::<S>,
            bi: bi_scalar::<S>,
            weighted_uni: weighted_uni_scalar::<S>,
            weighted_bi: weighted_bi_scalar::<S>,
            qpel_uni: qpel_uni_scalar::<S>,
            epel_uni: epel_uni_scalar::<S>,
            qpel_bi: qpel_bi_scalar::<S>,
            epel_bi: epel_bi_scalar::<S>,
            fused_mc: false,
            sao_band: sao_band_scalar::<S>,
            sao_edge: sao_edge_scalar::<S>,
            deblock_luma_v: |d, off, stride, beta, tc, np, nq, max| {
                deblock_luma_scalar(d, off, 1, stride, beta, tc, np, nq, max)
            },
            deblock_luma_h: |d, off, stride, beta, tc, np, nq, max| {
                deblock_luma_scalar(d, off, stride, 1, beta, tc, np, nq, max)
            },
            deblock_chroma_v: |d, off, stride, tc, np, nq, max| {
                deblock_chroma_scalar(d, off, 1, stride, tc, np, nq, max)
            },
            deblock_chroma_h: |d, off, stride, tc, np, nq, max| {
                deblock_chroma_scalar(d, off, stride, 1, tc, np, nq, max)
            },
            intra_planar: intra_planar_scalar::<S>,
            intra_dc: intra_dc_scalar::<S>,
            intra_angular: intra_angular_scalar::<S>,
        }
    }

    /// The best table for `cpu`.
    pub fn new(cpu: Cpu) -> Self {
        let mut d = Self::scalar();
        d.cpu = cpu;
        S::install_simd(&mut d, cpu);
        d
    }
}

impl HevcDsp<u16> {
    /// The scalar reference table (16-bit samples).
    pub const SCALAR: HevcDsp<u16> = HevcDsp {
        cpu: Cpu::SCALAR,
        idct: [
            idct_scalar::<4>,
            idct_scalar::<8>,
            idct_scalar::<16>,
            idct_scalar::<32>,
        ],
        idst4: idst4_scalar,
        add_residual: add_residual_scalar::<u16>,
        qpel_copy: copy_scalar::<u16>,
        qpel_h: qpel_h_scalar::<u16>,
        qpel_v: qpel_v_scalar::<u16>,
        qpel_v2: qpel_v2_scalar,
        epel_copy: copy_scalar::<u16>,
        epel_h: epel_h_scalar::<u16>,
        epel_v: epel_v_scalar::<u16>,
        epel_v2: epel_v2_scalar,
        uni: uni_scalar::<u16>,
        bi: bi_scalar::<u16>,
        weighted_uni: weighted_uni_scalar::<u16>,
        weighted_bi: weighted_bi_scalar::<u16>,
        qpel_uni: qpel_uni_scalar::<u16>,
        epel_uni: epel_uni_scalar::<u16>,
        qpel_bi: qpel_bi_scalar::<u16>,
        epel_bi: epel_bi_scalar::<u16>,
        fused_mc: false,
        sao_band: sao_band_scalar::<u16>,
        sao_edge: sao_edge_scalar::<u16>,
        deblock_luma_v: |d, off, stride, beta, tc, np, nq, max| {
            deblock_luma_scalar(d, off, 1, stride, beta, tc, np, nq, max)
        },
        deblock_luma_h: |d, off, stride, beta, tc, np, nq, max| {
            deblock_luma_scalar(d, off, stride, 1, beta, tc, np, nq, max)
        },
        deblock_chroma_v: |d, off, stride, tc, np, nq, max| {
            deblock_chroma_scalar(d, off, 1, stride, tc, np, nq, max)
        },
        deblock_chroma_h: |d, off, stride, tc, np, nq, max| {
            deblock_chroma_scalar(d, off, stride, 1, tc, np, nq, max)
        },
        intra_planar: intra_planar_scalar::<u16>,
        intra_dc: intra_dc_scalar::<u16>,
        intra_angular: intra_angular_scalar::<u16>,
    };
}

impl HevcDsp<u8> {
    /// The scalar reference table (8-bit samples).
    pub const SCALAR: HevcDsp<u8> = HevcDsp {
        cpu: Cpu::SCALAR,
        idct: [
            idct_scalar::<4>,
            idct_scalar::<8>,
            idct_scalar::<16>,
            idct_scalar::<32>,
        ],
        idst4: idst4_scalar,
        add_residual: add_residual_scalar::<u8>,
        qpel_copy: copy_scalar::<u8>,
        qpel_h: qpel_h_scalar::<u8>,
        qpel_v: qpel_v_scalar::<u8>,
        qpel_v2: qpel_v2_scalar,
        epel_copy: copy_scalar::<u8>,
        epel_h: epel_h_scalar::<u8>,
        epel_v: epel_v_scalar::<u8>,
        epel_v2: epel_v2_scalar,
        uni: uni_scalar::<u8>,
        bi: bi_scalar::<u8>,
        weighted_uni: weighted_uni_scalar::<u8>,
        weighted_bi: weighted_bi_scalar::<u8>,
        qpel_uni: qpel_uni_scalar::<u8>,
        epel_uni: epel_uni_scalar::<u8>,
        qpel_bi: qpel_bi_scalar::<u8>,
        epel_bi: epel_bi_scalar::<u8>,
        fused_mc: false,
        sao_band: sao_band_scalar::<u8>,
        sao_edge: sao_edge_scalar::<u8>,
        deblock_luma_v: |d, off, stride, beta, tc, np, nq, max| {
            deblock_luma_scalar(d, off, 1, stride, beta, tc, np, nq, max)
        },
        deblock_luma_h: |d, off, stride, beta, tc, np, nq, max| {
            deblock_luma_scalar(d, off, stride, 1, beta, tc, np, nq, max)
        },
        deblock_chroma_v: |d, off, stride, tc, np, nq, max| {
            deblock_chroma_scalar(d, off, 1, stride, tc, np, nq, max)
        },
        deblock_chroma_h: |d, off, stride, tc, np, nq, max| {
            deblock_chroma_scalar(d, off, stride, 1, tc, np, nq, max)
        },
        intra_planar: intra_planar_scalar::<u8>,
        intra_dc: intra_dc_scalar::<u8>,
        intra_angular: intra_angular_scalar::<u8>,
    };
}

/// SIMD kernels for 16-bit sample planes.
#[allow(unused_variables)]
pub fn install_simd_u16(d: &mut HevcDsp<u16>, cpu: Cpu) {
    // Widest last. The 128-bit ladder starts at SSE2, which every x86-64 CPU
    // has, so the scalar kernels below are a reference and not a fallback;
    // AVX2 then overwrites the entries it has a wider kernel for.
    #[cfg(target_arch = "x86_64")]
    super::hevc_x86_128::install_u16(d, cpu);
    #[cfg(target_arch = "x86_64")]
    if cpu.avx2 {
        super::hevc_avx2::install(d);
        // Over the top, never instead of: a kernel AVX-512 does not carry
        // keeps the AVX2 one it just replaced.
        if cpu.avx512 {
            super::hevc_avx512::install(d);
        }
    }
    #[cfg(target_arch = "aarch64")]
    if cpu.neon {
        super::hevc_neon::install(d);
    }
    #[cfg(all(target_arch = "wasm32", target_feature = "simd128"))]
    if cpu.simd128 {
        super::hevc_wasm128::install_u16(d);
    }
}

/// SIMD kernels for 8-bit sample planes.
#[allow(unused_variables)]
pub fn install_simd_u8(d: &mut HevcDsp<u8>, cpu: Cpu) {
    #[cfg(target_arch = "x86_64")]
    super::hevc_x86_128::install_u8(d, cpu);
    #[cfg(target_arch = "x86_64")]
    if cpu.avx2 {
        super::hevc_avx2_u8::install(d);
        if cpu.avx512 {
            super::hevc_avx512_u8::install(d);
        }
    }
    #[cfg(target_arch = "aarch64")]
    if cpu.neon {
        super::hevc_neon_u8::install(d);
        // Additive: each rung replaces only the kernels its instructions
        // actually improve, so a CPU without the extension keeps the ones
        // below it untouched.
        if cpu.dotprod {
            super::hevc_neon_u8::install_dotprod(d);
        }
    }
    #[cfg(all(target_arch = "wasm32", target_feature = "simd128"))]
    if cpu.simd128 {
        super::hevc_wasm128::install(d);
    }
}

// ----------------------------------------------------------------------
// Inverse transforms
// ----------------------------------------------------------------------

/// 1-D inverse DCT of `n` coefficients (`src[k * stride]`, only the first
/// `nz` possibly nonzero) into `out[0..n]`, no shift — the even/odd partial
/// butterfly, which is the matrix product regrouped (exact).
#[inline]
fn idct1(src: &[i16], stride: usize, n: usize, nz: usize, out: &mut [i32]) {
    if n == 1 {
        out[0] = 64 * src[0] as i32;
        return;
    }
    let half = n / 2;
    let mut e = [0i32; 16];
    idct1(src, stride * 2, half, nz.div_ceil(2), &mut e);
    let step = 32 / n;
    for k in 0..half {
        let mut o = 0i32;
        let mut j = 1;
        while j < nz {
            o += TRANSFORM32[j * step][k] as i32 * src[j * stride] as i32;
            j += 2;
        }
        out[k] = e[k] + o;
        out[n - 1 - k] = e[k] - o;
    }
}

/// Scalar inverse DCT (8.6.4.2), columns then rows, with the 16-bit clip
/// after the first stage.
fn idct_scalar<const N: usize>(coeffs: &mut [i16], bd_shift: i32, max_x: usize, max_y: usize) {
    let round2 = 1i32 << (bd_shift - 1);
    if max_x == 0 && max_y == 0 {
        // DC only: every output sample is the same.
        let v = ((coeffs[0] as i32 * 64 + 64) >> 7).clamp(-32768, 32767);
        let r = ((v * 64 + round2) >> bd_shift).clamp(-32768, 32767) as i16;
        coeffs[..N * N].fill(r);
        return;
    }
    let mut tmp = [0i16; 32 * 32];
    let mut out = [0i32; 32];
    // Columns 0..=max_x; the rest stay zero.
    for x in 0..=max_x {
        idct1(&coeffs[x..], N, N, max_y + 1, &mut out);
        for y in 0..N {
            tmp[y * N + x] = ((out[y] + 64) >> 7).clamp(-32768, 32767) as i16;
        }
    }
    // Rows.
    for y in 0..N {
        idct1(&tmp[y * N..], 1, N, max_x + 1, &mut out);
        for x in 0..N {
            coeffs[y * N + x] = ((out[x] + round2) >> bd_shift).clamp(-32768, 32767) as i16;
        }
    }
}

/// Inverse DST 4x4 (8.6.4.2, `trType == 1`).
fn idst4_scalar(coeffs: &mut [i16], bd_shift: i32, _max_x: usize, _max_y: usize) {
    const M: [[i32; 4]; 4] = [
        [29, 55, 74, 84],
        [74, 74, 0, -74],
        [84, -29, -74, 55],
        [55, -84, 74, -29],
    ];
    let round2 = 1i32 << (bd_shift - 1);
    let mut tmp = [0i16; 16];
    for x in 0..4 {
        for i in 0..4 {
            let mut s = 0i32;
            for j in 0..4 {
                s += M[j][i] * coeffs[j * 4 + x] as i32;
            }
            tmp[i * 4 + x] = ((s + 64) >> 7).clamp(-32768, 32767) as i16;
        }
    }
    for y in 0..4 {
        for i in 0..4 {
            let mut s = 0i32;
            for j in 0..4 {
                s += M[j][i] * tmp[y * 4 + j] as i32;
            }
            coeffs[y * 4 + i] = ((s + round2) >> bd_shift).clamp(-32768, 32767) as i16;
        }
    }
}

fn add_residual_scalar<S: Sample>(dst: &mut [S], stride: usize, res: &[i16], n: usize, max: i32) {
    for y in 0..n {
        let row = &mut dst[y * stride..y * stride + n];
        let r = &res[y * n..y * n + n];
        for x in 0..n {
            row[x] = S::from_i32((row[x].to_i32() + r[x] as i32).clamp(0, max));
        }
    }
}

// ----------------------------------------------------------------------
// The wide pipeline: `i32` coefficients / residuals (bit depths above 12,
// `extended_precision_processing_flag`), `i64` accumulation, scalar only.
// Exact inverses of the `i16` kernels above where their ranges overlap —
// the tests pin that.
// ----------------------------------------------------------------------

/// [`idct1`] over `i32` coefficients with `i64` sums: at a 22-bit coefficient
/// range, 32 products of 90 do not fit `i32`.
fn idct1_wide(src: &[i32], stride: usize, n: usize, nz: usize, out: &mut [i64]) {
    if n == 1 {
        out[0] = 64 * src[0] as i64;
        return;
    }
    let half = n / 2;
    let mut e = [0i64; 16];
    idct1_wide(src, stride * 2, half, nz.div_ceil(2), &mut e);
    let step = 32 / n;
    for k in 0..half {
        let mut o = 0i64;
        let mut j = 1;
        while j < nz {
            o += TRANSFORM32[j * step][k] as i64 * src[j * stride] as i64;
            j += 2;
        }
        out[k] = e[k] + o;
        out[n - 1 - k] = e[k] - o;
    }
}

/// Inverse DCT of an `n x n` (`n = 1 << log2`) block of `i32` coefficients
/// in place (8.6.4.2): the first stage clips to `±(1 << log2_range)`
/// (`coeffMin..=coeffMax`), the second shifts by `bd_shift` (`Max(20 -
/// BitDepth, extended ? 11 : 0)`) and, unlike the `i16` kernel, has nothing
/// to clip to — the residual is whatever the sum is.
pub fn idct_wide(
    coeffs: &mut [i32],
    log2: u32,
    log2_range: u32,
    bd_shift: i32,
    max_x: usize,
    max_y: usize,
) {
    let n = 1usize << log2;
    let (cmin, cmax) = (-(1i64 << log2_range), (1i64 << log2_range) - 1);
    let round2 = 1i64 << (bd_shift - 1);
    let mut tmp = [0i32; 32 * 32];
    let mut out = [0i64; 32];
    for x in 0..=max_x {
        idct1_wide(&coeffs[x..], n, n, max_y + 1, &mut out);
        for y in 0..n {
            tmp[y * n + x] = ((out[y] + 64) >> 7).clamp(cmin, cmax) as i32;
        }
    }
    for y in 0..n {
        idct1_wide(&tmp[y * n..], 1, n, max_x + 1, &mut out);
        for x in 0..n {
            coeffs[y * n + x] = ((out[x] + round2) >> bd_shift) as i32;
        }
    }
}

/// Inverse DST 4x4 on `i32` coefficients (see [`idct_wide`]).
pub fn idst4_wide(coeffs: &mut [i32], log2_range: u32, bd_shift: i32) {
    const M: [[i64; 4]; 4] = [
        [29, 55, 74, 84],
        [74, 74, 0, -74],
        [84, -29, -74, 55],
        [55, -84, 74, -29],
    ];
    let (cmin, cmax) = (-(1i64 << log2_range), (1i64 << log2_range) - 1);
    let round2 = 1i64 << (bd_shift - 1);
    let mut tmp = [0i64; 16];
    for x in 0..4 {
        for i in 0..4 {
            let mut s = 0i64;
            for j in 0..4 {
                s += M[j][i] * coeffs[j * 4 + x] as i64;
            }
            tmp[i * 4 + x] = ((s + 64) >> 7).clamp(cmin, cmax);
        }
    }
    for y in 0..4 {
        for i in 0..4 {
            let mut s = 0i64;
            for j in 0..4 {
                s += M[j][i] * tmp[y * 4 + j];
            }
            coeffs[y * 4 + i] = ((s + round2) >> bd_shift) as i32;
        }
    }
}

/// Add an `i32` residual block to `dst` with clipping to `0..=max`.
pub fn add_residual_wide<S: Sample>(dst: &mut [S], stride: usize, res: &[i32], n: usize, max: i32) {
    for y in 0..n {
        let row = &mut dst[y * stride..y * stride + n];
        let r = &res[y * n..y * n + n];
        for x in 0..n {
            row[x] =
                S::from_i32((row[x].to_i32() as i64 + r[x] as i64).clamp(0, max as i64) as i32);
        }
    }
}

// ----------------------------------------------------------------------
// Interpolation
// ----------------------------------------------------------------------

fn copy_scalar<S: Sample>(
    dst: &mut [i16],
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    shift: i32,
) {
    for y in 0..h {
        let s = &src[y * src_stride..y * src_stride + w];
        let d = &mut dst[y * w..y * w + w];
        for x in 0..w {
            d[x] = (s[x].to_i32() << shift) as i16;
        }
    }
}

fn qpel_h_scalar<S: Sample>(
    dst: &mut [i16],
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    frac: usize,
    shift: i32,
) {
    let f = &QPEL_FILTERS[frac];
    for y in 0..h {
        let base = y * src_stride;
        for x in 0..w {
            let mut acc = 0i32;
            for k in 0..8 {
                acc += f[k] as i32 * src[base + x + k].to_i32();
            }
            dst[y * w + x] = (acc >> shift) as i16;
        }
    }
}

fn qpel_v_scalar<S: Sample>(
    dst: &mut [i16],
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    frac: usize,
    shift: i32,
) {
    let f = &QPEL_FILTERS[frac];
    for y in 0..h {
        for x in 0..w {
            let mut acc = 0i32;
            for k in 0..8 {
                acc += f[k] as i32 * src[(y + k) * src_stride + x].to_i32();
            }
            dst[y * w + x] = (acc >> shift) as i16;
        }
    }
}

fn qpel_v2_scalar(
    dst: &mut [i16],
    src: &[i16],
    src_stride: usize,
    w: usize,
    h: usize,
    frac: usize,
) {
    let f = &QPEL_FILTERS[frac];
    for y in 0..h {
        for x in 0..w {
            let mut acc = 0i32;
            for k in 0..8 {
                acc += f[k] as i32 * src[(y + k) * src_stride + x] as i32;
            }
            dst[y * w + x] = (acc >> 6) as i16;
        }
    }
}

fn epel_h_scalar<S: Sample>(
    dst: &mut [i16],
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    frac: usize,
    shift: i32,
) {
    let f = &EPEL_FILTERS[frac];
    for y in 0..h {
        let base = y * src_stride;
        for x in 0..w {
            let mut acc = 0i32;
            for k in 0..4 {
                acc += f[k] as i32 * src[base + x + k].to_i32();
            }
            dst[y * w + x] = (acc >> shift) as i16;
        }
    }
}

fn epel_v_scalar<S: Sample>(
    dst: &mut [i16],
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    frac: usize,
    shift: i32,
) {
    let f = &EPEL_FILTERS[frac];
    for y in 0..h {
        for x in 0..w {
            let mut acc = 0i32;
            for k in 0..4 {
                acc += f[k] as i32 * src[(y + k) * src_stride + x].to_i32();
            }
            dst[y * w + x] = (acc >> shift) as i16;
        }
    }
}

fn epel_v2_scalar(
    dst: &mut [i16],
    src: &[i16],
    src_stride: usize,
    w: usize,
    h: usize,
    frac: usize,
) {
    let f = &EPEL_FILTERS[frac];
    for y in 0..h {
        for x in 0..w {
            let mut acc = 0i32;
            for k in 0..4 {
                acc += f[k] as i32 * src[(y + k) * src_stride + x] as i32;
            }
            dst[y * w + x] = (acc >> 6) as i16;
        }
    }
}

/// The two-pass scalar interpolation into `pred` (14-bit), for the fused
/// reference kernels: `src` starts at the window origin.
#[allow(clippy::too_many_arguments)]
fn interp_scalar<S: Sample>(
    luma: bool,
    pred: &mut [i16],
    tmp: &mut [i16],
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    fx: usize,
    fy: usize,
    bit_depth: u32,
) {
    let (reach, taps) = if luma { (3usize, 8usize) } else { (1, 4) };
    let shift1 = bit_depth.min(12) as i32 - 8;
    let shift3 = 14 - bit_depth as i32;
    let at_block = reach * src_stride + reach;
    match (fx, fy) {
        (0, 0) => copy_scalar(pred, &src[at_block..], src_stride, w, h, shift3),
        (_, 0) => {
            if luma {
                qpel_h_scalar(
                    pred,
                    &src[reach * src_stride..],
                    src_stride,
                    w,
                    h,
                    fx,
                    shift1,
                )
            } else {
                epel_h_scalar(
                    pred,
                    &src[reach * src_stride..],
                    src_stride,
                    w,
                    h,
                    fx,
                    shift1,
                )
            }
        }
        (0, _) => {
            if luma {
                qpel_v_scalar(pred, &src[reach..], src_stride, w, h, fy, shift1)
            } else {
                epel_v_scalar(pred, &src[reach..], src_stride, w, h, fy, shift1)
            }
        }
        _ => {
            let hh = h + taps - 1;
            if luma {
                qpel_h_scalar(tmp, src, src_stride, w, hh, fx, shift1);
                qpel_v2_scalar(pred, tmp, w, w, h, fy);
            } else {
                epel_h_scalar(tmp, src, src_stride, w, hh, fx, shift1);
                epel_v2_scalar(pred, tmp, w, w, h, fy);
            }
        }
    }
}

/// Where the fused reference kernels keep the 14-bit prediction in `tmp`.
const PRED_AT: usize = 64 * (64 + 7);

fn qpel_uni_scalar<S: Sample>(
    dst: &mut [S],
    dst_stride: usize,
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    fx: usize,
    fy: usize,
    tmp: &mut [i16],
    bit_depth: u32,
) {
    let (tmp, pred) = tmp.split_at_mut(PRED_AT);
    interp_scalar(true, pred, tmp, src, src_stride, w, h, fx, fy, bit_depth);
    uni_scalar(
        dst,
        dst_stride,
        pred,
        w,
        h,
        14 - bit_depth as i32,
        (1 << bit_depth) - 1,
    );
}

fn epel_uni_scalar<S: Sample>(
    dst: &mut [S],
    dst_stride: usize,
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    fx: usize,
    fy: usize,
    tmp: &mut [i16],
    bit_depth: u32,
) {
    let (tmp, pred) = tmp.split_at_mut(PRED_AT);
    interp_scalar(false, pred, tmp, src, src_stride, w, h, fx, fy, bit_depth);
    uni_scalar(
        dst,
        dst_stride,
        pred,
        w,
        h,
        14 - bit_depth as i32,
        (1 << bit_depth) - 1,
    );
}

#[allow(clippy::too_many_arguments)]
fn qpel_bi_scalar<S: Sample>(
    dst: &mut [S],
    dst_stride: usize,
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    fx: usize,
    fy: usize,
    tmp: &mut [i16],
    other: &[i16],
    bit_depth: u32,
) {
    let (tmp, pred) = tmp.split_at_mut(PRED_AT);
    interp_scalar(true, pred, tmp, src, src_stride, w, h, fx, fy, bit_depth);
    bi_scalar(
        dst,
        dst_stride,
        other,
        pred,
        w,
        h,
        15 - bit_depth as i32,
        (1 << bit_depth) - 1,
    );
}

#[allow(clippy::too_many_arguments)]
fn epel_bi_scalar<S: Sample>(
    dst: &mut [S],
    dst_stride: usize,
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    fx: usize,
    fy: usize,
    tmp: &mut [i16],
    other: &[i16],
    bit_depth: u32,
) {
    let (tmp, pred) = tmp.split_at_mut(PRED_AT);
    interp_scalar(false, pred, tmp, src, src_stride, w, h, fx, fy, bit_depth);
    bi_scalar(
        dst,
        dst_stride,
        other,
        pred,
        w,
        h,
        15 - bit_depth as i32,
        (1 << bit_depth) - 1,
    );
}

// ----------------------------------------------------------------------
// Combination / weighting
// ----------------------------------------------------------------------

fn uni_scalar<S: Sample>(
    dst: &mut [S],
    stride: usize,
    src: &[i16],
    w: usize,
    h: usize,
    shift: i32,
    max: i32,
) {
    let round = if shift > 0 { 1 << (shift - 1) } else { 0 };
    for y in 0..h {
        for x in 0..w {
            dst[y * stride + x] =
                S::from_i32(((src[y * w + x] as i32 + round) >> shift).clamp(0, max));
        }
    }
}

fn bi_scalar<S: Sample>(
    dst: &mut [S],
    stride: usize,
    a: &[i16],
    b: &[i16],
    w: usize,
    h: usize,
    shift: i32,
    max: i32,
) {
    let round = 1 << (shift - 1);
    for y in 0..h {
        for x in 0..w {
            dst[y * stride + x] = S::from_i32(
                ((a[y * w + x] as i32 + b[y * w + x] as i32 + round) >> shift).clamp(0, max),
            );
        }
    }
}

#[allow(clippy::too_many_arguments)]
fn weighted_uni_scalar<S: Sample>(
    dst: &mut [S],
    stride: usize,
    src: &[i16],
    w: usize,
    h: usize,
    log2_wd: i32,
    wt: i32,
    o: i32,
    max: i32,
) {
    if log2_wd >= 1 {
        let round = 1 << (log2_wd - 1);
        for y in 0..h {
            for x in 0..w {
                dst[y * stride + x] = S::from_i32(
                    (((src[y * w + x] as i32 * wt + round) >> log2_wd) + o).clamp(0, max),
                );
            }
        }
    } else {
        for y in 0..h {
            for x in 0..w {
                dst[y * stride + x] = S::from_i32((src[y * w + x] as i32 * wt + o).clamp(0, max));
            }
        }
    }
}

#[allow(clippy::too_many_arguments)]
fn weighted_bi_scalar<S: Sample>(
    dst: &mut [S],
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
    let round = (o0 + o1 + 1) << log2_wd;
    for y in 0..h {
        for x in 0..w {
            let v = (a[y * w + x] as i32 * w0 + b[y * w + x] as i32 * w1 + round) >> (log2_wd + 1);
            dst[y * stride + x] = S::from_i32(v.clamp(0, max));
        }
    }
}

// ----------------------------------------------------------------------
// Intra prediction
// ----------------------------------------------------------------------

fn intra_planar_scalar<S: Sample>(
    dst: &mut [S],
    stride: usize,
    left: &[u16],
    top: &[u16],
    n: usize,
) {
    let log2n = n.trailing_zeros();
    let (ln, tn) = (left[n] as i32, top[n] as i32);
    for y in 0..n {
        let row = &mut dst[y * stride..y * stride + n];
        let (ly, ry) = (left[y] as i32, n as i32 - 1 - y as i32);
        for (x, d) in row.iter_mut().enumerate() {
            let v = ((n as i32 - 1 - x as i32) * ly
                + (x as i32 + 1) * tn
                + ry * top[x] as i32
                + (y as i32 + 1) * ln
                + n as i32)
                >> (log2n + 1);
            *d = S::from_i32(v);
        }
    }
}

fn intra_dc_scalar<S: Sample>(
    dst: &mut [S],
    stride: usize,
    left: &[u16],
    top: &[u16],
    n: usize,
    edge: bool,
) {
    let log2n = n.trailing_zeros();
    let sum = n as i32
        + top[..n]
            .iter()
            .chain(&left[..n])
            .map(|&v| v as i32)
            .sum::<i32>();
    let dc = sum >> (log2n + 1);
    for y in 0..n {
        dst[y * stride..y * stride + n].fill(S::from_i32(dc));
    }
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

fn intra_angular_scalar<S: Sample>(
    dst: &mut [S],
    stride: usize,
    refs: &[u16],
    n: usize,
    angle: i32,
    transposed: bool,
) {
    for y in 0..n {
        let i_idx = ((y as i32 + 1) * angle) >> 5;
        let i_fact = ((y as i32 + 1) * angle) & 31;
        let start = (i_idx + 1 + n as i32) as usize;
        for x in 0..n {
            let (a, b) = (refs[start + x] as i32, refs[start + x + 1] as i32);
            let v = if i_fact != 0 {
                ((32 - i_fact) * a + i_fact * b + 16) >> 5
            } else {
                a
            };
            let at = if transposed {
                x * stride + y
            } else {
                y * stride + x
            };
            dst[at] = S::from_i32(v);
        }
    }
}

// ----------------------------------------------------------------------
// SAO
// ----------------------------------------------------------------------

#[allow(clippy::too_many_arguments)]
fn sao_band_scalar<S: Sample>(
    dst: &mut [S],
    dst_stride: usize,
    src: &[S],
    src_stride: usize,
    w: usize,
    h: usize,
    table: &[i16; 32],
    shift: i32,
    max: i32,
) {
    for y in 0..h {
        for x in 0..w {
            let v = src[y * src_stride + x].to_i32();
            dst[y * dst_stride + x] =
                S::from_i32((v + table[(v >> shift) as usize] as i32).clamp(0, max));
        }
    }
}

#[allow(clippy::too_many_arguments)]
fn sao_edge_scalar<S: Sample>(
    dst: &mut [S],
    src: &[S],
    origin: usize,
    stride: usize,
    w: usize,
    h: usize,
    na: isize,
    nb: isize,
    off: &[i16; 5],
    max: i32,
) {
    for y in 0..h {
        for x in 0..w {
            let i = origin + y * stride + x;
            let v = src[i].to_i32();
            let a = src[(i as isize + na) as usize].to_i32();
            let b = src[(i as isize + nb) as usize].to_i32();
            let e = (2 + (v - a).signum() + (v - b).signum()) as usize;
            dst[i] = S::from_i32((v + off[e] as i32).clamp(0, max));
        }
    }
}

#[cfg(test)]
mod tests {
    use super::*;

    /// The plain matrix product the butterfly must equal.
    fn idct_matrix(n: usize, coeffs: &[i16], bd_shift: i32) -> Vec<i16> {
        let step = 32 / n;
        let mut tmp = vec![0i32; n * n];
        for x in 0..n {
            for i in 0..n {
                let mut s = 0i64;
                for j in 0..n {
                    s += TRANSFORM32[j * step][i] as i64 * coeffs[j * n + x] as i64;
                }
                tmp[i * n + x] = ((s + 64) >> 7).clamp(-32768, 32767) as i32;
            }
        }
        let mut out = vec![0i16; n * n];
        let round = 1i64 << (bd_shift - 1);
        for y in 0..n {
            for i in 0..n {
                let mut s = 0i64;
                for j in 0..n {
                    s += TRANSFORM32[j * step][i] as i64 * tmp[y * n + j] as i64;
                }
                out[y * n + i] = ((s + round) >> bd_shift).clamp(-32768, 32767) as i16;
            }
        }
        out
    }

    fn lcg(seed: &mut u64) -> u32 {
        *seed = seed
            .wrapping_mul(6364136223846793005)
            .wrapping_add(1442695040888963407);
        (*seed >> 33) as u32
    }

    /// The wide kernels are the `i16` ones wherever both ranges hold: the
    /// same random blocks through both, at `log2TransformRange = 15`.
    #[test]
    fn wide_transforms_equal_the_i16_kernels_in_range() {
        let mut seed = 11u64;
        for &(n, log2) in &[(4usize, 2u32), (8, 3), (16, 4), (32, 5)] {
            for trial in 0..100 {
                let mut c = vec![0i16; n * n];
                let (mx, my) = if trial % 3 == 0 {
                    (n - 1, n - 1)
                } else {
                    ((lcg(&mut seed) as usize) % n, (lcg(&mut seed) as usize) % n)
                };
                for y in 0..=my {
                    for x in 0..=mx {
                        if lcg(&mut seed) % 3 == 0 {
                            // Small enough that the i16 kernel's output clip never bites.
                            c[y * n + x] = (lcg(&mut seed) as i32 % 2048 - 1024) as i16;
                        }
                    }
                }
                let bd_shift = 20 - 8 - (trial % 3) as i32 * 2;
                let mut want = c.clone();
                (HevcDsp::<u16>::SCALAR.idct[(log2 - 2) as usize])(&mut want, bd_shift, mx, my);
                let mut got: Vec<i32> = c.iter().map(|&v| v as i32).collect();
                idct_wide(&mut got, log2, 15, bd_shift, mx, my);
                assert_eq!(
                    got,
                    want.iter().map(|&v| v as i32).collect::<Vec<_>>(),
                    "n={n} trial={trial}"
                );
                if n == 4 {
                    let mut want = c.clone();
                    (HevcDsp::<u16>::SCALAR.idst4)(&mut want, bd_shift, mx, my);
                    let mut got: Vec<i32> = c.iter().map(|&v| v as i32).collect();
                    idst4_wide(&mut got, 15, bd_shift);
                    assert_eq!(
                        got,
                        want.iter().map(|&v| v as i32).collect::<Vec<_>>(),
                        "dst trial={trial}"
                    );
                }
            }
        }
        // add_residual: clipping at both ends, 16-bit samples.
        let mut a = vec![100u16, 65535, 0, 30000];
        let mut b = a.clone();
        let res16 = [-200i16, 5, -1, 32767];
        let res32: Vec<i32> = res16.iter().map(|&v| v as i32).collect();
        (HevcDsp::<u16>::SCALAR.add_residual)(&mut a, 2, &res16, 2, 65535);
        add_residual_wide(&mut b, 2, &res32, 2, 65535);
        assert_eq!(a, b);
        assert_eq!(a, [0, 65535, 0, 62767]);
        // And what only the wide one can express: a residual beyond i16.
        let mut c = vec![1000u16; 4];
        add_residual_wide(&mut c, 2, &[60000, -60000, 70000, -1], 2, 65535);
        assert_eq!(c, [61000, 0, 65535, 999]);
    }

    #[test]
    fn butterfly_equals_matrix() {
        let mut seed = 7u64;
        for &(n, log2) in &[(4usize, 2u32), (8, 3), (16, 4), (32, 5)] {
            for trial in 0..200 {
                let mut c = vec![0i16; n * n];
                // Sparse blocks with a bounding box, plus dense ones.
                let (mx, my) = if trial % 3 == 0 {
                    (n - 1, n - 1)
                } else {
                    ((lcg(&mut seed) as usize) % n, (lcg(&mut seed) as usize) % n)
                };
                for y in 0..=my {
                    for x in 0..=mx {
                        if lcg(&mut seed) % 3 == 0 {
                            c[y * n + x] = (lcg(&mut seed) as i32 % 65536 - 32768) as i16;
                        }
                    }
                }
                let bd_shift = 20 - 8 - (trial % 3) as i32 * 2;
                let want = idct_matrix(n, &c, bd_shift);
                let mut got = c.clone();
                (HevcDsp::<u16>::SCALAR.idct[(log2 - 2) as usize])(&mut got, bd_shift, mx, my);
                assert_eq!(got, want, "n={n} trial={trial}");
            }
        }
    }
}

// ----------------------------------------------------------------------
// Deblocking (scalar)
// ----------------------------------------------------------------------

/// Filter one 4-line luma edge segment. `pos` is the offset of q0 of the
/// first line, `step` the distance across the edge, `along` the distance
/// between lines.
#[allow(clippy::too_many_arguments)]
pub(crate) fn luma_edge_scalar<S: Sample>(
    d: &mut [S],
    pos: usize,
    step: usize,
    along: usize,
    beta: i32,
    tc: i32,
    no_p: bool,
    no_q: bool,
    max: i32,
) {
    let s = |d: &[S], line: usize, k: isize| -> i32 {
        d[(pos as isize + (line * along) as isize + k * step as isize) as usize].to_i32()
    };
    let dp0 = (s(d, 0, -3) - 2 * s(d, 0, -2) + s(d, 0, -1)).abs();
    let dp3 = (s(d, 3, -3) - 2 * s(d, 3, -2) + s(d, 3, -1)).abs();
    let dq0 = (s(d, 0, 2) - 2 * s(d, 0, 1) + s(d, 0, 0)).abs();
    let dq3 = (s(d, 3, 2) - 2 * s(d, 3, 1) + s(d, 3, 0)).abs();
    let dpq0 = dp0 + dq0;
    let dpq3 = dp3 + dq3;
    let dp = dp0 + dp3;
    let dq = dq0 + dq3;
    let dd = dpq0 + dpq3;
    if dd >= beta {
        return;
    }
    let dsam = |d: &[S], line: usize, dpq: i32| -> bool {
        dpq < (beta >> 2)
            && (s(d, line, -4) - s(d, line, -1)).abs() + (s(d, line, 0) - s(d, line, 3)).abs()
                < (beta >> 3)
            && (s(d, line, -1) - s(d, line, 0)).abs() < ((5 * tc + 1) >> 1)
    };
    let strong = dsam(d, 0, 2 * dpq0) && dsam(d, 3, 2 * dpq3);
    let dep = dp < ((beta + (beta >> 1)) >> 3);
    let deq = dq < ((beta + (beta >> 1)) >> 3);
    for line in 0..4 {
        let base = pos + line * along;
        let at = |k: isize| -> usize { (base as isize + k * step as isize) as usize };
        let p0 = d[at(-1)].to_i32();
        let p1 = d[at(-2)].to_i32();
        let p2 = d[at(-3)].to_i32();
        let p3 = d[at(-4)].to_i32();
        let q0 = d[at(0)].to_i32();
        let q1 = d[at(1)].to_i32();
        let q2 = d[at(2)].to_i32();
        let q3 = d[at(3)].to_i32();
        if strong {
            if !no_p {
                d[at(-1)] = S::from_i32(
                    ((p2 + 2 * p1 + 2 * p0 + 2 * q0 + q1 + 4) >> 3).clamp(p0 - 2 * tc, p0 + 2 * tc),
                );
                d[at(-2)] =
                    S::from_i32(((p2 + p1 + p0 + q0 + 2) >> 2).clamp(p1 - 2 * tc, p1 + 2 * tc));
                d[at(-3)] = S::from_i32(
                    ((2 * p3 + 3 * p2 + p1 + p0 + q0 + 4) >> 3).clamp(p2 - 2 * tc, p2 + 2 * tc),
                );
            }
            if !no_q {
                d[at(0)] = S::from_i32(
                    ((p1 + 2 * p0 + 2 * q0 + 2 * q1 + q2 + 4) >> 3).clamp(q0 - 2 * tc, q0 + 2 * tc),
                );
                d[at(1)] =
                    S::from_i32(((p0 + q0 + q1 + q2 + 2) >> 2).clamp(q1 - 2 * tc, q1 + 2 * tc));
                d[at(2)] = S::from_i32(
                    ((p0 + q0 + q1 + 3 * q2 + 2 * q3 + 4) >> 3).clamp(q2 - 2 * tc, q2 + 2 * tc),
                );
            }
        } else {
            let mut delta = (9 * (q0 - p0) - 3 * (q1 - p1) + 8) >> 4;
            if delta.abs() < tc * 10 {
                delta = delta.clamp(-tc, tc);
                if !no_p {
                    d[at(-1)] = S::from_i32((p0 + delta).clamp(0, max));
                }
                if !no_q {
                    d[at(0)] = S::from_i32((q0 - delta).clamp(0, max));
                }
                if dep && !no_p {
                    let dp = ((((p2 + p0 + 1) >> 1) - p1 + delta) >> 1).clamp(-(tc >> 1), tc >> 1);
                    d[at(-2)] = S::from_i32((p1 + dp).clamp(0, max));
                }
                if deq && !no_q {
                    let dq = ((((q2 + q0 + 1) >> 1) - q1 - delta) >> 1).clamp(-(tc >> 1), tc >> 1);
                    d[at(1)] = S::from_i32((q1 + dq).clamp(0, max));
                }
            }
        }
    }
}

/// Filter `n` lines of a chroma edge.
#[allow(clippy::too_many_arguments)]
pub(crate) fn chroma_edge_scalar<S: Sample>(
    d: &mut [S],
    pos: usize,
    step: usize,
    along: usize,
    n: usize,
    tc: i32,
    no_p: bool,
    no_q: bool,
    max: i32,
) {
    for line in 0..n {
        let base = pos + line * along;
        let at = |k: isize| -> usize { (base as isize + k * step as isize) as usize };
        let p0 = d[at(-1)].to_i32();
        let p1 = d[at(-2)].to_i32();
        let q0 = d[at(0)].to_i32();
        let q1 = d[at(1)].to_i32();
        let delta = ((((q0 - p0) << 2) + p1 - q1 + 4) >> 3).clamp(-tc, tc);
        if !no_p {
            d[at(-1)] = S::from_i32((p0 + delta).clamp(0, max));
        }
        if !no_q {
            d[at(0)] = S::from_i32((q0 - delta).clamp(0, max));
        }
    }
}

#[allow(clippy::too_many_arguments)]
fn deblock_luma_scalar<S: Sample>(
    d: &mut [S],
    off: usize,
    step: usize,
    along: usize,
    beta: [i32; 2],
    tc: [i32; 2],
    no_p: [bool; 2],
    no_q: [bool; 2],
    max: i32,
) {
    for seg in 0..2 {
        if beta[seg] == 0 && tc[seg] == 0 {
            continue;
        }
        luma_edge_scalar(
            d,
            off + 4 * seg * along,
            step,
            along,
            beta[seg],
            tc[seg],
            no_p[seg],
            no_q[seg],
            max,
        );
    }
}

#[allow(clippy::too_many_arguments)]
fn deblock_chroma_scalar<S: Sample>(
    d: &mut [S],
    off: usize,
    step: usize,
    along: usize,
    tc: [i32; 4],
    no_p: [bool; 4],
    no_q: [bool; 4],
    max: i32,
) {
    for seg in 0..4 {
        if tc[seg] == 0 {
            continue;
        }
        chroma_edge_scalar(
            d,
            off + 2 * seg * along,
            step,
            along,
            2,
            tc[seg],
            no_p[seg],
            no_q[seg],
            max,
        );
    }
}
