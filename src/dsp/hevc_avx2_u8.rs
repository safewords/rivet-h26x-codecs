//! AVX2 versions of the H.265 kernels for 8-bit sample planes (x86-64).
//!
//! Thirty-two 8-bit lanes per vector. Interpolation uses `pmaddubsw` on
//! interleaved neighbour pairs (samples `x, x+1` for horizontal taps, rows
//! `k, k+1` for vertical): each unsigned sample times its signed tap sums in
//! 16 bits, and the HEVC filters cannot overflow that for 8-bit input
//! (|sum| ≤ 255 · 112 = 28560), so the whole first stage runs in 16-bit
//! lanes — twice the width of the 16-bit-sample kernels. Combination and the
//! loop filters narrow to bytes with `packus`, whose saturation is exactly
//! the clip the standard asks for. The second (vertical over 16-bit) stage,
//! the inverse transform and the deblocking arithmetic are sample-size
//! independent and shared with [`super::hevc_avx2`]. Every kernel is checked
//! bit-exact against the scalar reference in the tests below.

#![cfg(target_arch = "x86_64")]

use std::arch::x86_64::*;

use super::hevc::HevcDsp;
use super::hevc_avx2 as w16;
use crate::hevc::tables::{EPEL_FILTERS, QPEL_FILTERS};

/// Replace the scalar entries of `d` with the AVX2 kernels.
pub fn install(d: &mut HevcDsp<u8>) {
    d.idct = [w16::idct_avx2::<4>, w16::idct_avx2::<8>, w16::idct_avx2::<16>, w16::idct_avx2::<32>];
    d.add_residual = add_residual_avx2;
    d.qpel_copy = copy_avx2;
    d.qpel_h = qpel_h_avx2;
    d.qpel_v = qpel_v_avx2;
    d.qpel_v2 = w16::qpel_v2_avx2;
    d.epel_copy = copy_avx2;
    d.epel_h = epel_h_avx2;
    d.epel_v = epel_v_avx2;
    d.epel_v2 = w16::epel_v2_avx2;
    d.uni = uni_avx2;
    d.bi = bi_avx2;
    d.weighted_uni = weighted_uni_avx2;
    d.weighted_bi = weighted_bi_avx2;
    d.qpel_uni = qpel_uni_avx2;
    d.epel_uni = epel_uni_avx2;
    d.qpel_bi = qpel_bi_avx2;
    d.epel_bi = epel_bi_avx2;
    d.fused_mc = true;
    d.sao_band = sao_band_avx2;
    d.sao_edge = sao_edge_avx2;
    d.deblock_luma_v = deblock_luma_v_avx2;
    d.deblock_luma_h = deblock_luma_h_avx2;
    d.deblock_chroma_v = deblock_chroma_v_avx2;
    d.deblock_chroma_h = deblock_chroma_h_avx2;
    d.intra_angular = intra_angular_avx2;
}

// ----------------------------------------------------------------------
// Helpers
// ----------------------------------------------------------------------

/// A pair of taps `(a, b)` as one 16-bit lane `a | b << 8` (the low byte
/// multiplies the even sample of an interleaved pair).
#[inline(always)]
pub(super) fn pair8(a: i8, b: i8) -> i16 {
    (a as u8 as i16) | ((b as i16) << 8)
}

/// Store the first `n` (≤ 16) bytes of `v`.
#[target_feature(enable = "avx2")]
#[inline]
unsafe fn store_bytes(dst: *mut u8, v: __m128i, n: usize) {
    unsafe {
        match n {
            16 => _mm_storeu_si128(dst as *mut __m128i, v),
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

/// Store the first `n` (≤ 32) bytes of `v`.
#[target_feature(enable = "avx2")]
#[inline]
unsafe fn store_bytes32(dst: *mut u8, v: __m256i, n: usize) {
    unsafe {
        if n == 32 {
            _mm256_storeu_si256(dst as *mut __m256i, v);
        } else if n > 16 {
            _mm_storeu_si128(dst as *mut __m128i, _mm256_castsi256_si128(v));
            store_bytes(dst.add(16), _mm256_extracti128_si256(v, 1), n - 16);
        } else {
            store_bytes(dst, _mm256_castsi256_si128(v), n);
        }
    }
}

/// Load 32 bytes, or the first `avail` zero-padded.
#[target_feature(enable = "avx2")]
#[inline]
unsafe fn load_bytes32(src: *const u8, avail: usize) -> __m256i {
    unsafe {
        if avail >= 32 {
            _mm256_loadu_si256(src as *const __m256i)
        } else if avail == 16 {
            _mm256_zextsi128_si256(_mm_loadu_si128(src as *const __m128i))
        } else {
            let mut t = [0u8; 32];
            std::ptr::copy_nonoverlapping(src, t.as_mut_ptr(), avail);
            _mm256_loadu_si256(t.as_ptr() as *const __m256i)
        }
    }
}

/// 16 i16 lanes to 16 bytes, saturating to `0..=255`.
#[target_feature(enable = "avx2")]
#[inline]
unsafe fn pack16(v: __m256i) -> __m128i {
    _mm_packus_epi16(_mm256_castsi256_si128(v), _mm256_extracti128_si256(v, 1))
}

/// Whether a block of width `w` is handled as one contiguous run of
/// samples (the predictions are stored with stride `w`, so a 2/4/8-wide
/// block is 8/4/2 rows per 16-lane vector instead of a mostly idle vector
/// per row).
#[inline(always)]
fn narrow(w: usize) -> bool {
    w == 8 || w == 4 || w == 2
}

/// Store 16 bytes of `p` as `rows` rows of `w` (2, 4 or 8) bytes.
#[target_feature(enable = "avx2")]
#[inline]
unsafe fn scatter_rows(dst: *mut u8, stride: usize, w: usize, p: __m128i, rows: usize) {
    unsafe {
        match w {
            8 => {
                _mm_storel_epi64(dst as *mut __m128i, p);
                if rows > 1 {
                    _mm_storel_epi64(dst.add(stride) as *mut __m128i, _mm_unpackhi_epi64(p, p));
                }
            }
            4 => {
                let mut t = [0u32; 4];
                _mm_storeu_si128(t.as_mut_ptr() as *mut __m128i, p);
                for r in 0..rows.min(4) {
                    std::ptr::write_unaligned(dst.add(r * stride) as *mut u32, t[r]);
                }
            }
            _ => {
                let mut t = [0u16; 8];
                _mm_storeu_si128(t.as_mut_ptr() as *mut __m128i, p);
                for r in 0..rows.min(8) {
                    std::ptr::write_unaligned(dst.add(r * stride) as *mut u16, t[r]);
                }
            }
        }
    }
}

/// Whether reading `w` samples starting `x` into a row of `stride`, for
/// `rows` rows, plus `extra` samples along, stays inside `len` for the
/// vector width the kernels use at that block width.
#[inline(always)]
pub(super) fn fits(len: usize, stride: usize, rows: usize, w: usize, extra: usize) -> bool {
    let (vec, last_x) = if w <= 8 {
        (8, 0)
    } else if w <= 16 {
        (16, 0)
    } else {
        (32, (w - 1) / 32 * 32)
    };
    (rows - 1) * stride + last_x + extra + vec <= len
}

// ----------------------------------------------------------------------
// Interpolation
// ----------------------------------------------------------------------

fn copy_avx2(dst: &mut [i16], src: &[u8], src_stride: usize, w: usize, h: usize, shift: i32) {
    // 16-byte loads at every 16-sample step of each row.
    if (h - 1) * src_stride + (w - 1) / 16 * 16 + 16 > src.len() {
        return (HevcDsp::<u8>::SCALAR.qpel_copy)(dst, src, src_stride, w, h, shift);
    }
    unsafe { copy_impl(dst, src, src_stride, w, h, shift) }
}

#[target_feature(enable = "avx2")]
unsafe fn copy_impl(dst: &mut [i16], src: &[u8], src_stride: usize, w: usize, h: usize, shift: i32) {
    unsafe {
        let sh = _mm_cvtsi32_si128(shift);
        if narrow(w) {
            // Several rows per vector; the output is contiguous.
            let rows_per = 16 / w;
            let mut y = 0;
            while y < h {
                let rows = (h - y).min(rows_per);
                let s = src.as_ptr().add(y * src_stride);
                let p = match w {
                    8 => {
                        let a = _mm_loadl_epi64(s as *const __m128i);
                        let b = if rows > 1 { _mm_loadl_epi64(s.add(src_stride) as *const __m128i) } else { a };
                        _mm_unpacklo_epi64(a, b)
                    }
                    4 => {
                        let rd = |r: usize| std::ptr::read_unaligned(s.add(r.min(rows - 1) * src_stride) as *const u32) as i32;
                        _mm_setr_epi32(rd(0), rd(1), rd(2), rd(3))
                    }
                    _ => {
                        let rd = |r: usize| std::ptr::read_unaligned(s.add(r.min(rows - 1) * src_stride) as *const u16) as i16;
                        _mm_setr_epi16(rd(0), rd(1), rd(2), rd(3), rd(4), rd(5), rd(6), rd(7))
                    }
                };
                let v = _mm256_sll_epi16(_mm256_cvtepu8_epi16(p), sh);
                w16::store_n(dst.as_mut_ptr().add(y * w), v, rows * w);
                y += rows_per;
            }
            return;
        }
        for y in 0..h {
            let s = src.as_ptr().add(y * src_stride);
            let d = dst.as_mut_ptr().add(y * w);
            let mut x = 0;
            while x < w {
                let v = _mm256_cvtepu8_epi16(_mm_loadu_si128(s.add(x) as *const __m128i));
                w16::store_n(d.add(x), _mm256_sll_epi16(v, sh), (w - x).min(16));
                x += 16;
            }
        }
    }
}

/// What a FIR stage produces, per output kind (`MODE_*`).
#[derive(Clone, Copy)]
pub(super) struct Out {
    /// `MODE_I16`: 14-bit predictions, stride `w`.
    pub(super) i16: *mut i16,
    /// `MODE_UNI` / `MODE_BI`: samples, stride `stride`.
    pub(super) u8: *mut u8,
    /// Sample stride.
    pub(super) stride: usize,
    /// `MODE_BI`: the other list's 14-bit prediction, stride `w`.
    pub(super) other: *const i16,
    /// Block width (the stride of `i16` and `other`).
    pub(super) w: usize,
}

/// 14-bit predictions (the two-pass path and the first stage of hv).
pub(super) const MODE_I16: u8 = 0;
/// Default-weighted uni-prediction samples: `(v + 32) >> 6`.
pub(super) const MODE_UNI: u8 = 1;
/// Default-weighted bi-prediction samples: `(v + other + 64) >> 7`.
pub(super) const MODE_BI: u8 = 2;

/// Emit 16 lanes of a stage's output (`v`, 14-bit) at (`row`, `x`), the
/// first `n` lanes.
#[target_feature(enable = "avx2")]
#[inline]
unsafe fn emit<const MODE: u8>(out: &Out, row: usize, x: usize, v: __m256i, n: usize) {
    unsafe {
        match MODE {
            MODE_I16 => w16::store_n(out.i16.add(row * out.w + x), v, n),
            MODE_UNI => {
                let r = _mm256_srai_epi16(_mm256_adds_epi16(v, _mm256_set1_epi16(32)), 6);
                store_bytes(out.u8.add(row * out.stride + x), pack16(r), n);
            }
            _ => {
                // Saturating sums, exact after the clip (see `bi_impl`).
                let o = w16::load_n(out.other.add(row * out.w + x), n);
                let r = _mm256_srai_epi16(_mm256_adds_epi16(_mm256_adds_epi16(v, o), _mm256_set1_epi16(64)), 7);
                store_bytes(out.u8.add(row * out.stride + x), pack16(r), n);
            }
        }
    }
}

/// Horizontal FIR with `TAPS` taps over bytes.
#[target_feature(enable = "avx2")]
#[inline]
pub(super) unsafe fn fir_h<const TAPS: usize, const MODE: u8>(out: &Out, src: *const u8, src_stride: usize, w: usize, h: usize, taps: &[i8], shift: i32) {
    unsafe {
        let mut c = [_mm256_setzero_si256(); 4];
        for k in 0..TAPS / 2 {
            c[k] = _mm256_set1_epi16(pair8(taps[2 * k], taps[2 * k + 1]));
        }
        let c8: [__m128i; 4] = [_mm256_castsi256_si128(c[0]), _mm256_castsi256_si128(c[1]), _mm256_castsi256_si128(c[2]), _mm256_castsi256_si128(c[3])];
        let sh = _mm_cvtsi32_si128(shift);
        if w <= 8 {
            // Narrow blocks: two rows per vector, one 128-bit lane each.
            let mut y = 0;
            while y + 1 < h {
                let s0 = src.add(y * src_stride);
                let s1 = s0.add(src_stride);
                let mut acc = _mm256_setzero_si256();
                for k in 0..TAPS / 2 {
                    let a = _mm256_setr_m128i(_mm_loadl_epi64(s0.add(2 * k) as *const __m128i), _mm_loadl_epi64(s1.add(2 * k) as *const __m128i));
                    let b = _mm256_setr_m128i(_mm_loadl_epi64(s0.add(2 * k + 1) as *const __m128i), _mm_loadl_epi64(s1.add(2 * k + 1) as *const __m128i));
                    acc = _mm256_add_epi16(acc, _mm256_maddubs_epi16(_mm256_unpacklo_epi8(a, b), c[k]));
                }
                let r = _mm256_sra_epi16(acc, sh);
                emit::<MODE>(out, y, 0, r, w);
                emit::<MODE>(out, y + 1, 0, _mm256_castsi128_si256(_mm256_extracti128_si256(r, 1)), w);
                y += 2;
            }
            if y < h {
                let s0 = src.add(y * src_stride);
                let mut acc = _mm_setzero_si128();
                for k in 0..TAPS / 2 {
                    let a = _mm_loadl_epi64(s0.add(2 * k) as *const __m128i);
                    let b = _mm_loadl_epi64(s0.add(2 * k + 1) as *const __m128i);
                    acc = _mm_add_epi16(acc, _mm_maddubs_epi16(_mm_unpacklo_epi8(a, b), c8[k]));
                }
                emit::<MODE>(out, y, 0, _mm256_castsi128_si256(_mm_sra_epi16(acc, sh)), w);
            }
            return;
        }
        if w <= 16 {
            for y in 0..h {
                let s = src.add(y * src_stride);
                let mut lo = _mm_setzero_si128();
                let mut hi = _mm_setzero_si128();
                for k in 0..TAPS / 2 {
                    let a = _mm_loadu_si128(s.add(2 * k) as *const __m128i);
                    let b = _mm_loadu_si128(s.add(2 * k + 1) as *const __m128i);
                    lo = _mm_add_epi16(lo, _mm_maddubs_epi16(_mm_unpacklo_epi8(a, b), c8[k]));
                    hi = _mm_add_epi16(hi, _mm_maddubs_epi16(_mm_unpackhi_epi8(a, b), c8[k]));
                }
                let r = _mm256_sra_epi16(_mm256_setr_m128i(lo, hi), sh);
                emit::<MODE>(out, y, 0, r, w);
            }
            return;
        }
        for y in 0..h {
            let s = src.add(y * src_stride);
            let mut x = 0;
            while x < w {
                let mut lo = _mm256_setzero_si256();
                let mut hi = _mm256_setzero_si256();
                for k in 0..TAPS / 2 {
                    let a = _mm256_loadu_si256(s.add(x + 2 * k) as *const __m256i);
                    let b = _mm256_loadu_si256(s.add(x + 2 * k + 1) as *const __m256i);
                    lo = _mm256_add_epi16(lo, _mm256_maddubs_epi16(_mm256_unpacklo_epi8(a, b), c[k]));
                    hi = _mm256_add_epi16(hi, _mm256_maddubs_epi16(_mm256_unpackhi_epi8(a, b), c[k]));
                }
                let lo = _mm256_sra_epi16(lo, sh);
                let hi = _mm256_sra_epi16(hi, sh);
                // lo = outputs 0..8 | 16..24, hi = 8..16 | 24..32.
                let n = w - x;
                emit::<MODE>(out, y, x, _mm256_permute2x128_si256(lo, hi, 0x20), n.min(16));
                if n > 16 {
                    emit::<MODE>(out, y, x + 16, _mm256_permute2x128_si256(lo, hi, 0x31), (n - 16).min(16));
                }
                x += 32;
            }
        }
    }
}

/// Vertical FIR with `TAPS` taps over byte rows.
#[target_feature(enable = "avx2")]
#[inline]
pub(super) unsafe fn fir_v<const TAPS: usize, const MODE: u8>(out: &Out, src: *const u8, src_stride: usize, w: usize, h: usize, taps: &[i8], shift: i32) {
    unsafe {
        let mut c = [_mm256_setzero_si256(); 4];
        for k in 0..TAPS / 2 {
            c[k] = _mm256_set1_epi16(pair8(taps[2 * k], taps[2 * k + 1]));
        }
        let c8: [__m128i; 4] = [_mm256_castsi256_si128(c[0]), _mm256_castsi256_si128(c[1]), _mm256_castsi256_si128(c[2]), _mm256_castsi256_si128(c[3])];
        let sh = _mm_cvtsi32_si128(shift);
        let row = |r: usize| src.add(r * src_stride);
        if w <= 8 {
            let mut y = 0;
            while y + 1 < h {
                let mut acc = _mm256_setzero_si256();
                for k in 0..TAPS / 2 {
                    let r0 = _mm_loadl_epi64(row(y + 2 * k) as *const __m128i);
                    let r1 = _mm_loadl_epi64(row(y + 2 * k + 1) as *const __m128i);
                    let r2 = _mm_loadl_epi64(row(y + 2 * k + 2) as *const __m128i);
                    let a = _mm256_setr_m128i(r0, r1);
                    let b = _mm256_setr_m128i(r1, r2);
                    acc = _mm256_add_epi16(acc, _mm256_maddubs_epi16(_mm256_unpacklo_epi8(a, b), c[k]));
                }
                let r = _mm256_sra_epi16(acc, sh);
                emit::<MODE>(out, y, 0, r, w);
                emit::<MODE>(out, y + 1, 0, _mm256_castsi128_si256(_mm256_extracti128_si256(r, 1)), w);
                y += 2;
            }
            if y < h {
                let mut acc = _mm_setzero_si128();
                for k in 0..TAPS / 2 {
                    let a = _mm_loadl_epi64(row(y + 2 * k) as *const __m128i);
                    let b = _mm_loadl_epi64(row(y + 2 * k + 1) as *const __m128i);
                    acc = _mm_add_epi16(acc, _mm_maddubs_epi16(_mm_unpacklo_epi8(a, b), c8[k]));
                }
                emit::<MODE>(out, y, 0, _mm256_castsi128_si256(_mm_sra_epi16(acc, sh)), w);
            }
            return;
        }
        if w <= 16 {
            for y in 0..h {
                let mut lo = _mm_setzero_si128();
                let mut hi = _mm_setzero_si128();
                for k in 0..TAPS / 2 {
                    let a = _mm_loadu_si128(row(y + 2 * k) as *const __m128i);
                    let b = _mm_loadu_si128(row(y + 2 * k + 1) as *const __m128i);
                    lo = _mm_add_epi16(lo, _mm_maddubs_epi16(_mm_unpacklo_epi8(a, b), c8[k]));
                    hi = _mm_add_epi16(hi, _mm_maddubs_epi16(_mm_unpackhi_epi8(a, b), c8[k]));
                }
                let r = _mm256_sra_epi16(_mm256_setr_m128i(lo, hi), sh);
                emit::<MODE>(out, y, 0, r, w);
            }
            return;
        }
        for y in 0..h {
            let mut x = 0;
            while x < w {
                let mut lo = _mm256_setzero_si256();
                let mut hi = _mm256_setzero_si256();
                for k in 0..TAPS / 2 {
                    let a = _mm256_loadu_si256(row(y + 2 * k).add(x) as *const __m256i);
                    let b = _mm256_loadu_si256(row(y + 2 * k + 1).add(x) as *const __m256i);
                    lo = _mm256_add_epi16(lo, _mm256_maddubs_epi16(_mm256_unpacklo_epi8(a, b), c[k]));
                    hi = _mm256_add_epi16(hi, _mm256_maddubs_epi16(_mm256_unpackhi_epi8(a, b), c[k]));
                }
                let lo = _mm256_sra_epi16(lo, sh);
                let hi = _mm256_sra_epi16(hi, sh);
                let n = w - x;
                emit::<MODE>(out, y, x, _mm256_permute2x128_si256(lo, hi, 0x20), n.min(16));
                if n > 16 {
                    emit::<MODE>(out, y, x + 16, _mm256_permute2x128_si256(lo, hi, 0x31), (n - 16).min(16));
                }
                x += 32;
            }
        }
    }
}

/// Vertical FIR with `TAPS` taps over 14-bit rows (the second stage of hv):
/// `pmaddwd` on interleaved row pairs, 32-bit sums, `>> 6`.
#[target_feature(enable = "avx2")]
#[inline]
unsafe fn fir_v2<const TAPS: usize, const MODE: u8>(out: &Out, src: *const i16, src_stride: usize, w: usize, h: usize, taps: &[i8]) {
    unsafe {
        let mut c = [_mm256_setzero_si256(); 4];
        for k in 0..TAPS / 2 {
            c[k] = _mm256_set1_epi32(pair16(taps[2 * k], taps[2 * k + 1]));
        }
        let row = |r: usize| src.add(r * src_stride);
        if w <= 8 {
            let c8: [__m128i; 4] = [_mm256_castsi256_si128(c[0]), _mm256_castsi256_si128(c[1]), _mm256_castsi256_si128(c[2]), _mm256_castsi256_si128(c[3])];
            for y in 0..h {
                let mut lo = _mm_setzero_si128();
                let mut hi = _mm_setzero_si128();
                for k in 0..TAPS / 2 {
                    let a = _mm_loadu_si128(row(y + 2 * k) as *const __m128i);
                    let b = _mm_loadu_si128(row(y + 2 * k + 1) as *const __m128i);
                    lo = _mm_add_epi32(lo, _mm_madd_epi16(_mm_unpacklo_epi16(a, b), c8[k]));
                    hi = _mm_add_epi32(hi, _mm_madd_epi16(_mm_unpackhi_epi16(a, b), c8[k]));
                }
                let r = _mm_packs_epi32(_mm_srai_epi32(lo, 6), _mm_srai_epi32(hi, 6));
                emit::<MODE>(out, y, 0, _mm256_castsi128_si256(r), w);
            }
            return;
        }
        for y in 0..h {
            let mut x = 0;
            while x < w {
                let mut lo = _mm256_setzero_si256();
                let mut hi = _mm256_setzero_si256();
                for k in 0..TAPS / 2 {
                    let a = _mm256_loadu_si256(row(y + 2 * k).add(x) as *const __m256i);
                    let b = _mm256_loadu_si256(row(y + 2 * k + 1).add(x) as *const __m256i);
                    lo = _mm256_add_epi32(lo, _mm256_madd_epi16(_mm256_unpacklo_epi16(a, b), c[k]));
                    hi = _mm256_add_epi32(hi, _mm256_madd_epi16(_mm256_unpackhi_epi16(a, b), c[k]));
                }
                let r = _mm256_packs_epi32(_mm256_srai_epi32(lo, 6), _mm256_srai_epi32(hi, 6));
                emit::<MODE>(out, y, x, r, (w - x).min(16));
                x += 16;
            }
        }
    }
}

/// A pair of taps `(a, b)` as one 32-bit lane `a | b << 16` (for `pmaddwd`).
#[inline(always)]
pub(super) fn pair16(a: i8, b: i8) -> i32 {
    (a as i16 as u16 as i32) | ((b as i16 as u16 as i32) << 16)
}

/// Whether the second stage's `w`-stride 14-bit rows can be read 16 (or 8)
/// lanes at a time for `rows` rows within `len`.
#[inline(always)]
fn fits_i16(len: usize, w: usize, rows: usize) -> bool {
    let vec = if w <= 8 { 8 } else { 16 };
    let last_x = if w <= 8 { 0 } else { (w - 1) / 16 * 16 };
    (rows - 1) * w + last_x + vec <= len
}

pub(super) fn qpel_h_avx2(dst: &mut [i16], src: &[u8], src_stride: usize, w: usize, h: usize, frac: usize, shift: i32) {
    if !fits(src.len(), src_stride, h, w, 7) || dst.len() < w * h {
        return (HevcDsp::<u8>::SCALAR.qpel_h)(dst, src, src_stride, w, h, frac, shift);
    }
    let out = Out { i16: dst.as_mut_ptr(), u8: std::ptr::null_mut(), stride: 0, other: std::ptr::null(), w };
    unsafe { fir_h::<8, MODE_I16>(&out, src.as_ptr(), src_stride, w, h, &QPEL_FILTERS[frac][..8], shift) }
}

pub(super) fn qpel_v_avx2(dst: &mut [i16], src: &[u8], src_stride: usize, w: usize, h: usize, frac: usize, shift: i32) {
    if !fits(src.len(), src_stride, h + 7, w, 0) || dst.len() < w * h {
        return (HevcDsp::<u8>::SCALAR.qpel_v)(dst, src, src_stride, w, h, frac, shift);
    }
    let out = Out { i16: dst.as_mut_ptr(), u8: std::ptr::null_mut(), stride: 0, other: std::ptr::null(), w };
    unsafe { fir_v::<8, MODE_I16>(&out, src.as_ptr(), src_stride, w, h, &QPEL_FILTERS[frac][..8], shift) }
}

pub(super) fn epel_h_avx2(dst: &mut [i16], src: &[u8], src_stride: usize, w: usize, h: usize, frac: usize, shift: i32) {
    if !fits(src.len(), src_stride, h, w, 3) || dst.len() < w * h {
        return (HevcDsp::<u8>::SCALAR.epel_h)(dst, src, src_stride, w, h, frac, shift);
    }
    let out = Out { i16: dst.as_mut_ptr(), u8: std::ptr::null_mut(), stride: 0, other: std::ptr::null(), w };
    unsafe { fir_h::<4, MODE_I16>(&out, src.as_ptr(), src_stride, w, h, &EPEL_FILTERS[frac], shift) }
}

pub(super) fn epel_v_avx2(dst: &mut [i16], src: &[u8], src_stride: usize, w: usize, h: usize, frac: usize, shift: i32) {
    if !fits(src.len(), src_stride, h + 3, w, 0) || dst.len() < w * h {
        return (HevcDsp::<u8>::SCALAR.epel_v)(dst, src, src_stride, w, h, frac, shift);
    }
    let out = Out { i16: dst.as_mut_ptr(), u8: std::ptr::null_mut(), stride: 0, other: std::ptr::null(), w };
    unsafe { fir_v::<4, MODE_I16>(&out, src.as_ptr(), src_stride, w, h, &EPEL_FILTERS[frac], shift) }
}

// ----------------------------------------------------------------------
// Fused interpolation + prediction
// ----------------------------------------------------------------------

/// Copy a `w x h` byte block (whole-sample uni-prediction: the prediction
/// is the reference block).
#[target_feature(enable = "avx2")]
unsafe fn copy_rows_u8(dst: *mut u8, dst_stride: usize, src: *const u8, src_stride: usize, w: usize, h: usize) {
    unsafe {
        for y in 0..h {
            let s = src.add(y * src_stride);
            let d = dst.add(y * dst_stride);
            let mut x = 0;
            while x < w {
                let n = w - x;
                if n >= 32 {
                    _mm256_storeu_si256(d.add(x) as *mut __m256i, _mm256_loadu_si256(s.add(x) as *const __m256i));
                    x += 32;
                } else if n >= 16 {
                    _mm_storeu_si128(d.add(x) as *mut __m128i, _mm_loadu_si128(s.add(x) as *const __m128i));
                    x += 16;
                } else if n >= 8 {
                    _mm_storel_epi64(d.add(x) as *mut __m128i, _mm_loadl_epi64(s.add(x) as *const __m128i));
                    x += 8;
                } else if n >= 4 {
                    std::ptr::write_unaligned(d.add(x) as *mut u32, std::ptr::read_unaligned(s.add(x) as *const u32));
                    x += 4;
                } else {
                    std::ptr::write_unaligned(d.add(x) as *mut u16, std::ptr::read_unaligned(s.add(x) as *const u16));
                    x += 2;
                }
            }
        }
    }
}

/// The fused kernels: `TAPS` (8 luma / 4 chroma), `MODE_UNI` or `MODE_BI`.
#[allow(clippy::too_many_arguments)]
fn fused<const TAPS: usize, const MODE: u8>(dst: &mut [u8], dst_stride: usize, src: &[u8], src_stride: usize, w: usize, h: usize, fx: usize, fy: usize, tmp: &mut [i16], other: &[i16]) {
    let reach = TAPS / 2 - 1;
    let at_block = reach * src_stride + reach;
    let hh = h + TAPS - 1;
    let ok = w >= 2
        && h >= 1
        && (h - 1) * dst_stride + w <= dst.len()
        && (MODE != MODE_BI || other.len() >= w * h)
        && tmp.len() >= super::hevc::MC_TMP_LEN
        && match (fx, fy) {
            (0, 0) => (h - 1) * src_stride + w + at_block <= src.len(),
            (_, 0) => src.len() > reach * src_stride && fits(src.len() - reach * src_stride, src_stride, h, w, TAPS - 1),
            (0, _) => src.len() > reach && fits(src.len() - reach, src_stride, hh, w, 0),
            _ => fits(src.len(), src_stride, hh, w, TAPS - 1) && fits_i16(super::hevc::MC_TMP_LEN, w, hh),
        };
    if !ok {
        let s = HevcDsp::<u8>::SCALAR;
        return match (TAPS, MODE) {
            (8, MODE_UNI) => (s.qpel_uni)(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, 8),
            (8, _) => (s.qpel_bi)(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, other, 8),
            (_, MODE_UNI) => (s.epel_uni)(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, 8),
            _ => (s.epel_bi)(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, other, 8),
        };
    }
    let (tx, ty): (&[i8], &[i8]) = if TAPS == 8 { (&QPEL_FILTERS[fx][..8], &QPEL_FILTERS[fy][..8]) } else { (&EPEL_FILTERS[fx], &EPEL_FILTERS[fy]) };
    let out = Out { i16: std::ptr::null_mut(), u8: dst.as_mut_ptr(), stride: dst_stride, other: other.as_ptr(), w };
    unsafe {
        match (fx, fy) {
            (0, 0) => {
                if MODE == MODE_UNI {
                    copy_rows_u8(dst.as_mut_ptr(), dst_stride, src.as_ptr().add(at_block), src_stride, w, h);
                } else {
                    // Whole-sample bi: widen, then the usual average.
                    let (pred, _) = tmp.split_at_mut(w * h);
                    copy_avx2(pred, &src[at_block..], src_stride, w, h, 6);
                    bi_impl(dst, dst_stride, other, pred, w, h, 7);
                }
            }
            (_, 0) => fir_h::<TAPS, MODE>(&out, src.as_ptr().add(reach * src_stride), src_stride, w, h, tx, 0),
            (0, _) => fir_v::<TAPS, MODE>(&out, src.as_ptr().add(reach), src_stride, w, h, ty, 0),
            _ => {
                let mid = Out { i16: tmp.as_mut_ptr(), u8: std::ptr::null_mut(), stride: 0, other: std::ptr::null(), w };
                fir_h::<TAPS, MODE_I16>(&mid, src.as_ptr(), src_stride, w, hh, tx, 0);
                fir_v2::<TAPS, MODE>(&out, tmp.as_ptr(), w, w, h, ty);
            }
        }
    }
}

pub(super) fn qpel_uni_avx2(dst: &mut [u8], dst_stride: usize, src: &[u8], src_stride: usize, w: usize, h: usize, fx: usize, fy: usize, tmp: &mut [i16], bit_depth: u32) {
    debug_assert_eq!(bit_depth, 8);
    fused::<8, MODE_UNI>(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, &[])
}

pub(super) fn epel_uni_avx2(dst: &mut [u8], dst_stride: usize, src: &[u8], src_stride: usize, w: usize, h: usize, fx: usize, fy: usize, tmp: &mut [i16], bit_depth: u32) {
    debug_assert_eq!(bit_depth, 8);
    fused::<4, MODE_UNI>(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, &[])
}

#[allow(clippy::too_many_arguments)]
pub(super) fn qpel_bi_avx2(dst: &mut [u8], dst_stride: usize, src: &[u8], src_stride: usize, w: usize, h: usize, fx: usize, fy: usize, tmp: &mut [i16], other: &[i16], bit_depth: u32) {
    debug_assert_eq!(bit_depth, 8);
    fused::<8, MODE_BI>(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, other)
}

#[allow(clippy::too_many_arguments)]
pub(super) fn epel_bi_avx2(dst: &mut [u8], dst_stride: usize, src: &[u8], src_stride: usize, w: usize, h: usize, fx: usize, fy: usize, tmp: &mut [i16], other: &[i16], bit_depth: u32) {
    debug_assert_eq!(bit_depth, 8);
    fused::<4, MODE_BI>(dst, dst_stride, src, src_stride, w, h, fx, fy, tmp, other)
}

// ----------------------------------------------------------------------
// Combination / weighting
// ----------------------------------------------------------------------

fn uni_avx2(dst: &mut [u8], stride: usize, src: &[i16], w: usize, h: usize, shift: i32, max: i32) {
    debug_assert_eq!(max, 255);
    unsafe { uni_impl(dst, stride, src, w, h, shift) }
}

#[target_feature(enable = "avx2")]
unsafe fn uni_impl(dst: &mut [u8], stride: usize, src: &[i16], w: usize, h: usize, shift: i32) {
    unsafe {
        let round = _mm256_set1_epi16(if shift > 0 { 1 << (shift - 1) } else { 0 });
        let sh = _mm_cvtsi32_si128(shift);
        if narrow(w) {
            let total = w * h;
            let mut i = 0;
            while i < total {
                let n = (total - i).min(16);
                let s = w16::load_n(src.as_ptr().add(i), total - i);
                let v = _mm256_sra_epi16(_mm256_adds_epi16(s, round), sh);
                scatter_rows(dst.as_mut_ptr().add((i / w) * stride), stride, w, pack16(v), n / w);
                i += 16;
            }
            return;
        }
        for y in 0..h {
            let mut x = 0;
            while x < w {
                let n = (w - x).min(16);
                let s = w16::load_n(src.as_ptr().add(y * w + x), w - x);
                // 14-bit + round fits i16 (< 16384 + 8192).
                let v = _mm256_sra_epi16(_mm256_adds_epi16(s, round), sh);
                store_bytes(dst.as_mut_ptr().add(y * stride + x), pack16(v), n);
                x += 16;
            }
        }
    }
}

fn bi_avx2(dst: &mut [u8], stride: usize, a: &[i16], b: &[i16], w: usize, h: usize, shift: i32, max: i32) {
    debug_assert_eq!(max, 255);
    unsafe { bi_impl(dst, stride, a, b, w, h, shift) }
}

#[target_feature(enable = "avx2")]
unsafe fn bi_impl(dst: &mut [u8], stride: usize, a: &[i16], b: &[i16], w: usize, h: usize, shift: i32) {
    unsafe {
        let round = _mm256_set1_epi16(1 << (shift - 1));
        let sh = _mm_cvtsi32_si128(shift);
        if narrow(w) {
            let total = w * h;
            let mut i = 0;
            while i < total {
                let n = (total - i).min(16);
                let va = w16::load_n(a.as_ptr().add(i), total - i);
                let vb = w16::load_n(b.as_ptr().add(i), total - i);
                let v = _mm256_sra_epi16(_mm256_adds_epi16(_mm256_adds_epi16(va, vb), round), sh);
                scatter_rows(dst.as_mut_ptr().add((i / w) * stride), stride, w, pack16(v), n / w);
                i += 16;
            }
            return;
        }
        for y in 0..h {
            let mut x = 0;
            while x < w {
                let n = (w - x).min(16);
                let va = w16::load_n(a.as_ptr().add(y * w + x), w - x);
                let vb = w16::load_n(b.as_ptr().add(y * w + x), w - x);
                // Saturating sums: a + b can exceed i16 only when both are
                // far above the 8-bit range, and then the clip to 255 gives
                // the same answer as the exact 32-bit sum would.
                let v = _mm256_sra_epi16(_mm256_adds_epi16(_mm256_adds_epi16(va, vb), round), sh);
                store_bytes(dst.as_mut_ptr().add(y * stride + x), pack16(v), n);
                x += 16;
            }
        }
    }
}

#[allow(clippy::too_many_arguments)]
fn weighted_uni_avx2(dst: &mut [u8], stride: usize, src: &[i16], w: usize, h: usize, log2_wd: i32, wt: i32, o: i32, max: i32) {
    debug_assert_eq!(max, 255);
    unsafe { weighted_uni_impl(dst, stride, src, w, h, log2_wd, wt, o) }
}

#[target_feature(enable = "avx2")]
#[allow(clippy::too_many_arguments)]
unsafe fn weighted_uni_impl(dst: &mut [u8], stride: usize, src: &[i16], w: usize, h: usize, log2_wd: i32, wt: i32, o: i32) {
    unsafe {
        let round = _mm256_set1_epi32(if log2_wd >= 1 { 1 << (log2_wd - 1) } else { 0 });
        let sh = _mm_cvtsi32_si128(log2_wd.max(0));
        let wv = _mm256_set1_epi32(wt);
        let ov = _mm256_set1_epi32(o);
        let weigh = |s: __m256i| -> __m128i {
            let lo = _mm256_cvtepi16_epi32(_mm256_castsi256_si128(s));
            let hi = _mm256_cvtepi16_epi32(_mm256_extracti128_si256(s, 1));
            let lo = _mm256_add_epi32(_mm256_sra_epi32(_mm256_add_epi32(_mm256_mullo_epi32(lo, wv), round), sh), ov);
            let hi = _mm256_add_epi32(_mm256_sra_epi32(_mm256_add_epi32(_mm256_mullo_epi32(hi, wv), round), sh), ov);
            pack16(_mm256_permute4x64_epi64(_mm256_packs_epi32(lo, hi), 0b11_01_10_00))
        };
        if narrow(w) {
            let total = w * h;
            let mut i = 0;
            while i < total {
                let n = (total - i).min(16);
                let s = w16::load_n(src.as_ptr().add(i), total - i);
                scatter_rows(dst.as_mut_ptr().add((i / w) * stride), stride, w, weigh(s), n / w);
                i += 16;
            }
            return;
        }
        for y in 0..h {
            let mut x = 0;
            while x < w {
                let n = (w - x).min(16);
                let s = w16::load_n(src.as_ptr().add(y * w + x), w - x);
                store_bytes(dst.as_mut_ptr().add(y * stride + x), weigh(s), n);
                x += 16;
            }
        }
    }
}

#[allow(clippy::too_many_arguments)]
fn weighted_bi_avx2(dst: &mut [u8], stride: usize, a: &[i16], b: &[i16], w: usize, h: usize, log2_wd: i32, w0: i32, w1: i32, o0: i32, o1: i32, max: i32) {
    debug_assert_eq!(max, 255);
    unsafe { weighted_bi_impl(dst, stride, a, b, w, h, log2_wd, w0, w1, o0, o1) }
}

#[target_feature(enable = "avx2")]
#[allow(clippy::too_many_arguments)]
unsafe fn weighted_bi_impl(dst: &mut [u8], stride: usize, a: &[i16], b: &[i16], w: usize, h: usize, log2_wd: i32, w0: i32, w1: i32, o0: i32, o1: i32) {
    unsafe {
        let round = _mm256_set1_epi32((o0 + o1 + 1) << log2_wd);
        let sh = _mm_cvtsi32_si128(log2_wd + 1);
        let w0v = _mm256_set1_epi32(w0);
        let w1v = _mm256_set1_epi32(w1);
        let weigh = |va: __m256i, vb: __m256i| -> __m128i {
            let alo = _mm256_cvtepi16_epi32(_mm256_castsi256_si128(va));
            let ahi = _mm256_cvtepi16_epi32(_mm256_extracti128_si256(va, 1));
            let blo = _mm256_cvtepi16_epi32(_mm256_castsi256_si128(vb));
            let bhi = _mm256_cvtepi16_epi32(_mm256_extracti128_si256(vb, 1));
            let lo = _mm256_sra_epi32(_mm256_add_epi32(_mm256_add_epi32(_mm256_mullo_epi32(alo, w0v), _mm256_mullo_epi32(blo, w1v)), round), sh);
            let hi = _mm256_sra_epi32(_mm256_add_epi32(_mm256_add_epi32(_mm256_mullo_epi32(ahi, w0v), _mm256_mullo_epi32(bhi, w1v)), round), sh);
            pack16(_mm256_permute4x64_epi64(_mm256_packs_epi32(lo, hi), 0b11_01_10_00))
        };
        if narrow(w) {
            let total = w * h;
            let mut i = 0;
            while i < total {
                let n = (total - i).min(16);
                let va = w16::load_n(a.as_ptr().add(i), total - i);
                let vb = w16::load_n(b.as_ptr().add(i), total - i);
                scatter_rows(dst.as_mut_ptr().add((i / w) * stride), stride, w, weigh(va, vb), n / w);
                i += 16;
            }
            return;
        }
        for y in 0..h {
            let mut x = 0;
            while x < w {
                let n = (w - x).min(16);
                let va = w16::load_n(a.as_ptr().add(y * w + x), w - x);
                let vb = w16::load_n(b.as_ptr().add(y * w + x), w - x);
                store_bytes(dst.as_mut_ptr().add(y * stride + x), weigh(va, vb), n);
                x += 16;
            }
        }
    }
}

// ----------------------------------------------------------------------
// Residual add
// ----------------------------------------------------------------------

fn add_residual_avx2(dst: &mut [u8], stride: usize, res: &[i16], n: usize, max: i32) {
    debug_assert_eq!(max, 255);
    unsafe { add_residual_impl(dst, stride, res, n) }
}

#[target_feature(enable = "avx2")]
unsafe fn add_residual_impl(dst: &mut [u8], stride: usize, res: &[i16], n: usize) {
    unsafe {
        match n {
            n if n >= 32 => {
                for y in 0..n {
                    let mut x = 0;
                    while x < n {
                        let d = dst.as_mut_ptr().add(y * stride + x);
                        let p = _mm256_loadu_si256(d as *const __m256i);
                        let r0 = _mm256_loadu_si256(res.as_ptr().add(y * n + x) as *const __m256i);
                        let r1 = _mm256_loadu_si256(res.as_ptr().add(y * n + x + 16) as *const __m256i);
                        let lo = _mm256_add_epi16(_mm256_cvtepu8_epi16(_mm256_castsi256_si128(p)), r0);
                        let hi = _mm256_add_epi16(_mm256_cvtepu8_epi16(_mm256_extracti128_si256(p, 1)), r1);
                        let v = _mm256_permute4x64_epi64(_mm256_packus_epi16(lo, hi), 0b11_01_10_00);
                        _mm256_storeu_si256(d as *mut __m256i, v);
                        x += 32;
                    }
                }
            }
            16 => {
                for y in 0..16 {
                    let d = dst.as_mut_ptr().add(y * stride);
                    let p = _mm256_cvtepu8_epi16(_mm_loadu_si128(d as *const __m128i));
                    let r = _mm256_loadu_si256(res.as_ptr().add(y * 16) as *const __m256i);
                    _mm_storeu_si128(d as *mut __m128i, pack16(_mm256_add_epi16(p, r)));
                }
            }
            8 => {
                // Two rows per vector.
                for y in (0..8).step_by(2) {
                    let d0 = dst.as_mut_ptr().add(y * stride);
                    let d1 = d0.add(stride);
                    let p = _mm256_cvtepu8_epi16(_mm_unpacklo_epi64(_mm_loadl_epi64(d0 as *const __m128i), _mm_loadl_epi64(d1 as *const __m128i)));
                    let r = _mm256_loadu_si256(res.as_ptr().add(y * 8) as *const __m256i);
                    let v = pack16(_mm256_add_epi16(p, r));
                    _mm_storel_epi64(d0 as *mut __m128i, v);
                    _mm_storel_epi64(d1 as *mut __m128i, _mm_unpackhi_epi64(v, v));
                }
            }
            _ => {
                // 4x4: all four rows in one vector.
                let d = dst.as_mut_ptr();
                let rd = |k: usize| std::ptr::read_unaligned(d.add(k * stride) as *const u32) as i32;
                let p = _mm256_cvtepu8_epi16(_mm_setr_epi32(rd(0), rd(1), rd(2), rd(3)));
                let r = _mm256_loadu_si256(res.as_ptr() as *const __m256i);
                let v = pack16(_mm256_add_epi16(p, r));
                let mut t = [0u32; 4];
                _mm_storeu_si128(t.as_mut_ptr() as *mut __m128i, v);
                for k in 0..4 {
                    std::ptr::write_unaligned(d.add(k * stride) as *mut u32, t[k]);
                }
            }
        }
    }
}

// ----------------------------------------------------------------------
// SAO
// ----------------------------------------------------------------------

/// `v + off` on bytes, clipped to `0..=255`, with `off` in `-128..=127`.
#[target_feature(enable = "avx2")]
#[inline]
unsafe fn add_offset_u8(v: __m256i, off: __m256i) -> __m256i {
    let zero = _mm256_setzero_si256();
    let pos = _mm256_max_epi8(off, zero);
    let neg = _mm256_max_epi8(_mm256_sub_epi8(zero, off), zero);
    _mm256_subs_epu8(_mm256_adds_epu8(v, pos), neg)
}

#[allow(clippy::too_many_arguments)]
fn sao_band_avx2(dst: &mut [u8], dst_stride: usize, src: &[u8], src_stride: usize, w: usize, h: usize, table: &[i16; 32], shift: i32, max: i32) {
    if shift != 3 || table.iter().any(|&o| !(-128..=127).contains(&o)) {
        return (HevcDsp::<u8>::SCALAR.sao_band)(dst, dst_stride, src, src_stride, w, h, table, shift, max);
    }
    debug_assert_eq!(max, 255);
    unsafe { sao_band_impl(dst, dst_stride, src, src_stride, w, h, table, shift) }
}

#[target_feature(enable = "avx2")]
#[allow(clippy::too_many_arguments)]
unsafe fn sao_band_impl(dst: &mut [u8], dst_stride: usize, src: &[u8], src_stride: usize, w: usize, h: usize, table: &[i16; 32], shift: i32) {
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
        let mask = _mm256_set1_epi8((0xFFu32 << shift) as u8 as i8);
        let bv: [__m256i; 4] = std::array::from_fn(|i| _mm256_set1_epi8(bands[i] as i8));
        let ov: [__m256i; 4] = std::array::from_fn(|i| _mm256_set1_epi8(offs[i]));
        for y in 0..h {
            let mut x = 0;
            while x < w {
                let n = (w - x).min(32);
                let v = load_bytes32(src.as_ptr().add(y * src_stride + x), n);
                let band = _mm256_and_si256(v, mask);
                let mut off = _mm256_setzero_si256();
                for i in 0..k {
                    off = _mm256_blendv_epi8(off, ov[i], _mm256_cmpeq_epi8(band, bv[i]));
                }
                store_bytes32(dst.as_mut_ptr().add(y * dst_stride + x), add_offset_u8(v, off), n);
                x += 32;
            }
        }
    }
}

#[allow(clippy::too_many_arguments)]
fn sao_edge_avx2(dst: &mut [u8], src: &[u8], origin: usize, stride: usize, w: usize, h: usize, na: isize, nb: isize, off: &[i16; 5], max: i32) {
    if off.iter().any(|&o| !(-128..=127).contains(&o)) {
        return (HevcDsp::<u8>::SCALAR.sao_edge)(dst, src, origin, stride, w, h, na, nb, off, max);
    }
    debug_assert_eq!(max, 255);
    unsafe { sao_edge_impl(dst, src, origin, stride, w, h, na, nb, off) }
}

#[target_feature(enable = "avx2")]
#[allow(clippy::too_many_arguments)]
unsafe fn sao_edge_impl(dst: &mut [u8], src: &[u8], origin: usize, stride: usize, w: usize, h: usize, na: isize, nb: isize, off: &[i16; 5]) {
    unsafe {
        // edgeIdx = 2 + sign(v-a) + sign(v-b) in 0..=4 indexes the offsets
        // through a byte shuffle.
        let o = |i: usize| off[i] as i8;
        let tab = _mm256_setr_epi8(
            o(0), o(1), o(2), o(3), o(4), 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0,
            o(0), o(1), o(2), o(3), o(4), 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0,
        );
        let two = _mm256_set1_epi8(2);
        let lo_reach = na.min(nb).min(0);
        let hi_reach = na.max(nb).max(0);
        for y in 0..h {
            let mut x = 0;
            while x < w {
                let n = (w - x).min(32);
                let i = origin + y * stride + x;
                if (i as isize + lo_reach) < 0 || (i as isize + hi_reach) as usize + 32 > src.len() || i + 32 > dst.len() {
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
                let v = _mm256_loadu_si256(src.as_ptr().add(i) as *const __m256i);
                let a = _mm256_loadu_si256(src.as_ptr().offset(i as isize + na) as *const __m256i);
                let b = _mm256_loadu_si256(src.as_ptr().offset(i as isize + nb) as *const __m256i);
                // Unsigned compares: ge = (max(v, a) == v), gt = ge & !eq, lt = !ge.
                let ge_a = _mm256_cmpeq_epi8(_mm256_max_epu8(v, a), v);
                let gt_a = _mm256_andnot_si256(_mm256_cmpeq_epi8(v, a), ge_a);
                let ge_b = _mm256_cmpeq_epi8(_mm256_max_epu8(v, b), v);
                let gt_b = _mm256_andnot_si256(_mm256_cmpeq_epi8(v, b), ge_b);
                // e = 2 + gt_a - lt_a + gt_b - lt_b with masks of -1: 2 - gt + lt.
                let ones = _mm256_cmpeq_epi8(v, v);
                let lt_a = _mm256_xor_si256(ge_a, ones);
                let lt_b = _mm256_xor_si256(ge_b, ones);
                let e = _mm256_add_epi8(_mm256_sub_epi8(_mm256_sub_epi8(two, gt_a), gt_b), _mm256_add_epi8(lt_a, lt_b));
                let o = _mm256_shuffle_epi8(tab, e);
                store_bytes32(dst.as_mut_ptr().add(i), add_offset_u8(v, o), n);
                x += 32;
            }
        }
    }
}

// ----------------------------------------------------------------------
// Deblocking — the shared i32-lane filters with byte loads and stores.
// ----------------------------------------------------------------------

/// Eight consecutive bytes as 8 x i32.
#[target_feature(enable = "avx2")]
#[inline]
unsafe fn ld8_u8(p: *const u8) -> __m256i {
    unsafe { _mm256_cvtepu8_epi32(_mm_loadl_epi64(p as *const __m128i)) }
}

/// 8 x i32 (each within a byte) to eight bytes in the low half.
#[target_feature(enable = "avx2")]
#[inline]
unsafe fn pack8_u8(v: __m256i) -> __m128i {
    unsafe {
        let p = w16::pack8_u16(v);
        _mm_packus_epi16(p, p)
    }
}

#[allow(clippy::too_many_arguments)]
fn deblock_luma_v_avx2(data: &mut [u8], off: usize, stride: usize, beta: [i32; 2], tc: [i32; 2], no_p: [bool; 2], no_q: [bool; 2], max: i32) {
    if (beta[0] == 0 && tc[0] == 0) && (beta[1] == 0 && tc[1] == 0) {
        return;
    }
    assert!(off >= 4 && off + 7 * stride + 4 <= data.len());
    unsafe { deblock_luma_v_impl(data.as_mut_ptr().add(off), stride, beta, tc, no_p, no_q, max) }
}

#[target_feature(enable = "avx2")]
#[allow(clippy::too_many_arguments)]
unsafe fn deblock_luma_v_impl(data: *mut u8, stride: usize, beta: [i32; 2], tc: [i32; 2], no_p: [bool; 2], no_q: [bool; 2], max: i32) {
    unsafe {
        let mut r = [_mm_setzero_si128(); 8];
        for i in 0..8 {
            r[i] = _mm_cvtepu8_epi16(_mm_loadl_epi64(data.add(i * stride).sub(4) as *const __m128i));
        }
        w16::transpose8_u16(&mut r);
        let mut v: w16::Lines8 = [_mm256_setzero_si256(); 8];
        for k in 0..8 {
            v[k] = _mm256_cvtepu16_epi32(r[k]);
        }
        w16::luma_filter8(&mut v, beta, tc, no_p, no_q, max);
        for k in 0..8 {
            r[k] = w16::pack8_u16(v[k]);
        }
        w16::transpose8_u16(&mut r);
        for i in 0..8 {
            _mm_storel_epi64(data.add(i * stride).sub(4) as *mut __m128i, _mm_packus_epi16(r[i], r[i]));
        }
    }
}

#[allow(clippy::too_many_arguments)]
fn deblock_luma_h_avx2(data: &mut [u8], off: usize, stride: usize, beta: [i32; 2], tc: [i32; 2], no_p: [bool; 2], no_q: [bool; 2], max: i32) {
    if (beta[0] == 0 && tc[0] == 0) && (beta[1] == 0 && tc[1] == 0) {
        return;
    }
    assert!(off >= 4 * stride && off + 3 * stride + 8 <= data.len());
    unsafe { deblock_luma_h_impl(data.as_mut_ptr().add(off), stride, beta, tc, no_p, no_q, max) }
}

#[target_feature(enable = "avx2")]
#[allow(clippy::too_many_arguments)]
unsafe fn deblock_luma_h_impl(data: *mut u8, stride: usize, beta: [i32; 2], tc: [i32; 2], no_p: [bool; 2], no_q: [bool; 2], max: i32) {
    unsafe {
        let mut v: w16::Lines8 = [_mm256_setzero_si256(); 8];
        for k in 0..8 {
            v[k] = ld8_u8(data.offset((k as isize - 4) * stride as isize));
        }
        w16::luma_filter8(&mut v, beta, tc, no_p, no_q, max);
        for k in 1..7 {
            _mm_storel_epi64(data.offset((k as isize - 4) * stride as isize) as *mut __m128i, pack8_u8(v[k]));
        }
    }
}

fn deblock_chroma_v_avx2(data: &mut [u8], off: usize, stride: usize, tc: [i32; 4], no_p: [bool; 4], no_q: [bool; 4], max: i32) {
    if tc.iter().all(|&t| t == 0) {
        return;
    }
    assert!(off >= 2 && off + 7 * stride + 2 <= data.len());
    unsafe { deblock_chroma_v_impl(data.as_mut_ptr().add(off), stride, tc, no_p, no_q, max) }
}

#[target_feature(enable = "avx2")]
unsafe fn deblock_chroma_v_impl(data: *mut u8, stride: usize, tc: [i32; 4], no_p: [bool; 4], no_q: [bool; 4], max: i32) {
    unsafe {
        let mut r = [_mm_setzero_si128(); 8];
        for i in 0..8 {
            let q = std::ptr::read_unaligned(data.add(i * stride).sub(2) as *const u32);
            r[i] = _mm_cvtepu8_epi16(_mm_cvtsi32_si128(q as i32));
        }
        let a0 = _mm_unpacklo_epi16(r[0], r[1]);
        let a1 = _mm_unpacklo_epi16(r[2], r[3]);
        let a2 = _mm_unpacklo_epi16(r[4], r[5]);
        let a3 = _mm_unpacklo_epi16(r[6], r[7]);
        let b0 = _mm_unpacklo_epi32(a0, a1); // p1 r0..3 | p0 r0..3
        let b1 = _mm_unpackhi_epi32(a0, a1); // q0 r0..3 | q1 r0..3
        let b2 = _mm_unpacklo_epi32(a2, a3);
        let b3 = _mm_unpackhi_epi32(a2, a3);
        let mut v = [
            _mm256_cvtepu16_epi32(_mm_unpacklo_epi64(b0, b2)),
            _mm256_cvtepu16_epi32(_mm_unpackhi_epi64(b0, b2)),
            _mm256_cvtepu16_epi32(_mm_unpacklo_epi64(b1, b3)),
            _mm256_cvtepu16_epi32(_mm_unpackhi_epi64(b1, b3)),
        ];
        w16::chroma_filter8(&mut v, tc, no_p, no_q, max);
        // (p0, q0) byte pairs per row.
        let p0 = w16::pack8_u16(v[1]);
        let q0 = w16::pack8_u16(v[2]);
        let pairs = _mm_packus_epi16(_mm_unpacklo_epi16(p0, q0), _mm_unpackhi_epi16(p0, q0));
        let mut t = [0u16; 8];
        _mm_storeu_si128(t.as_mut_ptr() as *mut __m128i, pairs);
        for i in 0..8 {
            std::ptr::write_unaligned(data.add(i * stride).sub(1) as *mut u16, t[i]);
        }
    }
}

fn deblock_chroma_h_avx2(data: &mut [u8], off: usize, stride: usize, tc: [i32; 4], no_p: [bool; 4], no_q: [bool; 4], max: i32) {
    if tc.iter().all(|&t| t == 0) {
        return;
    }
    assert!(off >= 2 * stride && off + stride + 8 <= data.len());
    unsafe { deblock_chroma_h_impl(data.as_mut_ptr().add(off), stride, tc, no_p, no_q, max) }
}

#[target_feature(enable = "avx2")]
unsafe fn deblock_chroma_h_impl(data: *mut u8, stride: usize, tc: [i32; 4], no_p: [bool; 4], no_q: [bool; 4], max: i32) {
    unsafe {
        let mut v = [ld8_u8(data.sub(2 * stride)), ld8_u8(data.sub(stride)), ld8_u8(data), ld8_u8(data.add(stride))];
        w16::chroma_filter8(&mut v, tc, no_p, no_q, max);
        _mm_storel_epi64(data.sub(stride) as *mut __m128i, pack8_u8(v[1]));
        _mm_storel_epi64(data as *mut __m128i, pack8_u8(v[2]));
    }
}

// ----------------------------------------------------------------------
// Intra prediction: the angular modes (8.4.4.2.6)
// ----------------------------------------------------------------------
//
// `((32 - f) * ref[x + i + 1] + f * ref[x + i + 2] + 16) >> 5` is one
// `pmaddubsw` of the interleaved neighbour bytes against the byte pair
// `(32 - f, f)` — both weights fit a signed byte and the sum, at most
// 32 * 255, an i16 — and the rounding shift one `pmulhrsw` by 1 << 10:
// `(s * 1024 + (1 << 14)) >> 15 = (s + 16) >> 5` for every such `s`. A
// zero fraction weighs the pair `(32, 0)`, which is the copy the standard
// asks for, so no row needs its own path. A row of 32 samples is two
// multiplies, where the 16-bit-sample kernel the 8-bit table used before
// took eight. The references are packed to bytes once per call (they are
// u16 for both tables); the rows go out 32, 16 x 2 or 8 x 2 a vector
// depending on the block size, and a 4x4 block's four in one.

/// Angular prediction of an `n x n` 8-bit block (`n` 4 to 32) from `refs`
/// (`ref[k]` at `refs[k + n]`), as [`HevcDsp::intra_angular`].
fn intra_angular_avx2(dst: &mut [u8], stride: usize, refs: &[u16], n: usize, angle: i32, transposed: bool) {
    let reach = angular_pack_len(n);
    let fits = n >= 4 && (n - 1) * stride + n <= dst.len();
    if n == 4 {
        if refs.len() < 16 || !fits || !(-32..=32).contains(&angle) {
            return (HevcDsp::<u8>::SCALAR.intra_angular)(dst, stride, refs, n, angle, transposed);
        }
        // SAFETY: AVX2 as above; `refs` holds 16 elements and `dst` the
        // block's last sample.
        return unsafe { intra_angular4_impl(dst.as_mut_ptr(), stride, refs, angle, transposed) };
    }
    if !matches!(n, 8 | 16 | 32) || !fits || refs.len() < reach || !(-32..=32).contains(&angle) {
        return (HevcDsp::<u8>::SCALAR.intra_angular)(dst, stride, refs, n, angle, transposed);
    }
    // SAFETY: `install` only puts this kernel in a table built for a CPU
    // with AVX2. `refs` holds `reach` elements and `dst` the block's last
    // sample (checked above); every load and store in the kernel is inside
    // those, as its documentation says.
    unsafe { intra_angular_impl(dst.as_mut_ptr(), stride, refs, n, angle, transposed) }
}

/// How many references the kernel packs to bytes: `ref[]` spans
/// `refs[0..3n + 2]`, and the last row's vector loads, `max(n, 8)` bytes
/// from `refs[2n + 1]` and `refs[2n + 2]`, reach `2n + 2 + max(n, 8)`;
/// eight at a time.
fn angular_pack_len(n: usize) -> usize {
    (3 * n + 2).max(2 * n + 2 + n.max(8)).next_multiple_of(8)
}

/// A 4x4 block in one vector, with no per-row scalar work. Its fourteen
/// references fit one register as bytes, so row `y`'s pairs `(r[s + x],
/// r[s + x + 1])`, `s = 5 + iIdx`, are one `pshufb` whose control is a
/// fixed pattern plus `s` broadcast over the row's eight bytes, and its
/// weights the `(32 - f, f)` pair broadcast likewise; `iIdx` and `f` for
/// the four rows come out of one multiply of `(1, 2, 3, 4)` by the angle.
/// Every byte the shuffles select is one of `r[1..=13]`.
///
/// # Safety
/// AVX2. `refs` holds at least 16 elements, `|angle| <= 32`, and `dst` is
/// writable for a 4x4 block at row pitch `stride`.
#[target_feature(enable = "avx2")]
unsafe fn intra_angular4_impl(dst: *mut u8, stride: usize, refs: &[u16], angle: i32, transposed: bool) {
    unsafe {
        let p = refs.as_ptr() as *const __m128i;
        let r = _mm256_broadcastsi128_si256(_mm_packus_epi16(_mm_loadu_si128(p), _mm_loadu_si128(p.add(1))));
        // (y + 1) * angle for rows 0-3, in the low four 16-bit lanes.
        let pos = _mm_mullo_epi16(_mm_setr_epi16(1, 2, 3, 4, 0, 0, 0, 0), _mm_set1_epi16(angle as i16));
        let start = _mm_add_epi16(_mm_srai_epi16::<5>(pos), _mm_set1_epi16(5));
        let f = _mm_and_si128(pos, _mm_set1_epi16(31));
        // `(32 - f) | f << 8`: the byte pair `pmaddubsw` wants.
        let w = _mm_or_si128(_mm_sub_epi16(_mm_set1_epi16(32), f), _mm_slli_epi16::<8>(f));
        // Each row's start byte over its eight control bytes, plus the
        // pair pattern; each row's weight pair over its four pairs.
        let spread = |lo: i8, hi: i8| _mm_setr_epi8(lo, lo, lo, lo, lo, lo, lo, lo, hi, hi, hi, hi, hi, hi, hi, hi);
        let pattern = _mm_setr_epi8(0, 1, 1, 2, 2, 3, 3, 4, 0, 1, 1, 2, 2, 3, 3, 4);
        let ctl = _mm256_setr_m128i(
            _mm_add_epi8(_mm_shuffle_epi8(start, spread(0, 2)), pattern),
            _mm_add_epi8(_mm_shuffle_epi8(start, spread(4, 6)), pattern),
        );
        let wpair = |a: i8, b: i8| _mm_setr_epi8(a, a + 1, a, a + 1, a, a + 1, a, a + 1, b, b + 1, b, b + 1, b, b + 1, b, b + 1);
        let wts = _mm256_setr_m128i(_mm_shuffle_epi8(w, wpair(0, 2)), _mm_shuffle_epi8(w, wpair(4, 6)));
        let v = angular_madd(_mm256_shuffle_epi8(r, ctl), wts);
        // Rows 0, 1 in the low lane's first eight bytes, 2, 3 in the high's.
        let v = _mm256_packus_epi16(v, v);
        let mut b = _mm_unpacklo_epi64(_mm256_castsi256_si128(v), _mm256_extracti128_si256::<1>(v));
        if transposed {
            b = _mm_shuffle_epi8(b, _mm_setr_epi8(0, 4, 8, 12, 1, 5, 9, 13, 2, 6, 10, 14, 3, 7, 11, 15));
        }
        for (y, q) in [b, _mm_srli_si128::<4>(b), _mm_srli_si128::<8>(b), _mm_srli_si128::<12>(b)].into_iter().enumerate() {
            std::ptr::write_unaligned(dst.add(y * stride) as *mut u32, _mm_cvtsi128_si32(q) as u32);
        }
    }
}

/// Eight interleaved `(ref[k], ref[k + 1])` byte pairs per 128-bit lane
/// times `w` (the `(32 - f, f)` pair in every 16-bit lane), rounded and
/// shifted: sixteen predictions as i16, eight a lane.
#[target_feature(enable = "avx2")]
#[inline]
fn angular_madd(pairs: __m256i, w: __m256i) -> __m256i {
    _mm256_mulhrs_epi16(_mm256_maddubs_epi16(pairs, w), _mm256_set1_epi16(1 << 10))
}

/// The weight pair of row `y` and the offset of its first reference,
/// `n + iIdx + 1`, into the packed references.
#[inline(always)]
fn angular_row(y: usize, n: usize, angle: i32) -> (i16, usize) {
    let pos = (y as i32 + 1) * angle;
    let (i, f) = (pos >> 5, pos & 31);
    (pair8((32 - f) as i8, f as i8), (n as i32 + i + 1) as usize)
}

/// # Safety
/// AVX2. `refs` holds at least `angular_pack_len(n)` elements,
/// `n` is 8, 16 or 32, `|angle| <= 32`, and `dst` is writable for an
/// `n x n` block at row pitch `stride`.
#[target_feature(enable = "avx2")]
unsafe fn intra_angular_impl(dst: *mut u8, stride: usize, refs: &[u16], n: usize, angle: i32, transposed: bool) {
    unsafe {
        // The references as bytes. Row `y` reads `r[s..=s + n]` with
        // `s = n + iIdx + 1` in `1..=2n + 1`, so at most `r[3n + 1]`. The
        // vector loads of a row reach `r[s + max(n, 8)]` at most, which
        // `angular_pack_len` covers, so every byte loaded was written here
        // first; whatever lies past `3n + 1` lands in lanes no store keeps.
        // A u8 table's references are all below 256, so `packus` only
        // narrows.
        let mut r = std::mem::MaybeUninit::<[u8; 104]>::uninit();
        let rp = r.as_mut_ptr() as *mut u8;
        let mut k = 0;
        while k < angular_pack_len(n) {
            let v = _mm_loadu_si128(refs.as_ptr().add(k) as *const __m128i);
            _mm_storel_epi64(rp.add(k) as *mut __m128i, _mm_packus_epi16(v, v));
            k += 8;
        }
        let rp = rp as *const u8;
        // Transposed (the horizontal modes): predict into a scratch block
        // of pitch `n`, then transpose it into place.
        // Every byte of its `n x n` corner is written before the transpose
        // reads it, and nothing else of it is read, so it is not cleared:
        // clearing a kilobyte a call costs a 4x4 block more than predicting it.
        let mut tmp = std::mem::MaybeUninit::<[u8; 32 * 32]>::uninit();
        let (out, pitch) = if transposed { (tmp.as_mut_ptr() as *mut u8, n) } else { (dst, stride) };
        match n {
            32 => {
                for y in 0..32 {
                    let (w, s) = angular_row(y, n, angle);
                    let a = _mm256_loadu_si256(rp.add(s) as *const __m256i);
                    let b = _mm256_loadu_si256(rp.add(s + 1) as *const __m256i);
                    let w = _mm256_set1_epi16(w);
                    let lo = angular_madd(_mm256_unpacklo_epi8(a, b), w);
                    let hi = angular_madd(_mm256_unpackhi_epi8(a, b), w);
                    // Within each 128-bit lane `lo` holds samples 0-7
                    // (16-23) and `hi` 8-15 (24-31): the in-lane pack puts
                    // them back in order.
                    _mm256_storeu_si256(out.add(y * pitch) as *mut __m256i, _mm256_packus_epi16(lo, hi));
                }
            }
            16 => {
                // Two rows a vector, one per 128-bit lane.
                for y in (0..16).step_by(2) {
                    let (w0, s0) = angular_row(y, n, angle);
                    let (w1, s1) = angular_row(y + 1, n, angle);
                    let a = _mm256_loadu2_m128i(rp.add(s1) as *const __m128i, rp.add(s0) as *const __m128i);
                    let b = _mm256_loadu2_m128i(rp.add(s1 + 1) as *const __m128i, rp.add(s0 + 1) as *const __m128i);
                    let w = _mm256_setr_m128i(_mm_set1_epi16(w0), _mm_set1_epi16(w1));
                    let lo = angular_madd(_mm256_unpacklo_epi8(a, b), w);
                    let hi = angular_madd(_mm256_unpackhi_epi8(a, b), w);
                    let v = _mm256_packus_epi16(lo, hi);
                    _mm_storeu_si128(out.add(y * pitch) as *mut __m128i, _mm256_castsi256_si128(v));
                    _mm_storeu_si128(out.add((y + 1) * pitch) as *mut __m128i, _mm256_extracti128_si256::<1>(v));
                }
            }
            8 => {
                for y in (0..8).step_by(2) {
                    let (w0, s0) = angular_row(y, n, angle);
                    let (w1, s1) = angular_row(y + 1, n, angle);
                    let a = _mm256_setr_m128i(_mm_loadl_epi64(rp.add(s0) as *const __m128i), _mm_loadl_epi64(rp.add(s1) as *const __m128i));
                    let b = _mm256_setr_m128i(_mm_loadl_epi64(rp.add(s0 + 1) as *const __m128i), _mm_loadl_epi64(rp.add(s1 + 1) as *const __m128i));
                    let w = _mm256_setr_m128i(_mm_set1_epi16(w0), _mm_set1_epi16(w1));
                    let v = angular_madd(_mm256_unpacklo_epi8(a, b), w);
                    let v = _mm256_packus_epi16(v, v);
                    _mm_storel_epi64(out.add(y * pitch) as *mut __m128i, _mm256_castsi256_si128(v));
                    _mm_storel_epi64(out.add((y + 1) * pitch) as *mut __m128i, _mm256_extracti128_si256::<1>(v));
                }
            }
            _ => unreachable!("angular {n}x{n} is not this kernel's"),
        }
        if !transposed {
            return;
        }
        let t = tmp.as_ptr() as *const u8;
        // 8x8 byte tiles: three rounds of unpacks turn eight rows into
        // eight columns.
        for by in (0..n).step_by(8) {
            for bx in (0..n).step_by(8) {
                let ld = |j: usize| _mm_loadl_epi64(t.add((by + j) * n + bx) as *const __m128i);
                let t0 = _mm_unpacklo_epi8(ld(0), ld(1));
                let t1 = _mm_unpacklo_epi8(ld(2), ld(3));
                let t2 = _mm_unpacklo_epi8(ld(4), ld(5));
                let t3 = _mm_unpacklo_epi8(ld(6), ld(7));
                let u0 = _mm_unpacklo_epi16(t0, t1);
                let u1 = _mm_unpackhi_epi16(t0, t1);
                let u2 = _mm_unpacklo_epi16(t2, t3);
                let u3 = _mm_unpackhi_epi16(t2, t3);
                // Columns 0-1, 2-3, 4-5 and 6-7 of the tile, eight bytes each.
                let cols = [_mm_unpacklo_epi32(u0, u2), _mm_unpackhi_epi32(u0, u2), _mm_unpacklo_epi32(u1, u3), _mm_unpackhi_epi32(u1, u3)];
                for (j, c) in cols.into_iter().enumerate() {
                    let o = dst.add((bx + 2 * j) * stride + by);
                    _mm_storel_epi64(o as *mut __m128i, c);
                    _mm_storel_epi64(o.add(stride) as *mut __m128i, _mm_unpackhi_epi64(c, c));
                }
            }
        }
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use crate::dsp::hevc::HevcDsp;

    fn lcg(seed: &mut u64) -> u32 {
        *seed = seed.wrapping_mul(6364136223846793005).wrapping_add(1442695040888963407);
        (*seed >> 33) as u32
    }

    fn avx2() -> Option<HevcDsp<u8>> {
        if !std::is_x86_feature_detected!("avx2") {
            eprintln!("no AVX2 on this host: kernel tests skipped");
            return None;
        }
        let mut d = HevcDsp::<u8>::SCALAR;
        install(&mut d);
        Some(d)
    }

    /// The angular predictor against the scalar reference on its own: every
    /// angle the kernel accepts (not only the 33 the standard uses), both
    /// orientations, every size, random and extreme references, and a
    /// destination pitch wider than the block whose padding must survive.
    #[test]
    fn intra_angular_matches_scalar_u8() {
        let Some(d) = avx2() else { return };
        let s = HevcDsp::<u8>::SCALAR;
        let mut seed = 0x5eed_u64;
        let mut checked = 0;
        for trial in 0..4 {
            for n in [4usize, 8, 16, 32] {
                // As `predict_prepared` sizes it: `3n + 2` references plus
                // the slack the SIMD kernels may read.
                let refs: Vec<u16> = (0..super::angular_pack_len(n))
                    .map(|_| match trial {
                        0 | 1 => (lcg(&mut seed) & 255) as u16,
                        2 => [0u16, 255][(lcg(&mut seed) & 1) as usize],
                        _ => 255,
                    })
                    .collect();
                for angle in -32..=32 {
                    for transposed in [false, true] {
                        for stride in [n, n + 5, 64] {
                            let mut a = vec![0x5au8; stride * n + 8];
                            let mut b = a.clone();
                            (s.intra_angular)(&mut a, stride, &refs, n, angle, transposed);
                            (d.intra_angular)(&mut b, stride, &refs, n, angle, transposed);
                            assert_eq!(a, b, "{n}x{n} angle {angle} transposed {transposed} stride {stride} trial {trial}");
                            checked += 1;
                        }
                    }
                }
            }
        }
        assert_eq!(checked, 4 * 4 * 65 * 2 * 3);
    }

    /// ns per call, scalar against the 128-bit AVX table and this one, over
    /// every mode the encoder's search tries. `cargo test --release
    /// intra_angular_bench -- --ignored --nocapture`.
    #[test]
    #[ignore = "timing, not a check"]
    fn intra_angular_bench() {
        let Some(d) = avx2() else { return };
        let s = HevcDsp::<u8>::SCALAR;
        let avx = HevcDsp::<u8>::new(crate::dsp::Cpu { avx2: false, avx512: false, avx512vnni: false, ..crate::dsp::Cpu::detect() });
        let mut seed = 9u64;
        let refs: Vec<u16> = (0..3 * 32 + 2 + 8).map(|_| (lcg(&mut seed) & 255) as u16).collect();
        let angles: [i32; 33] = [32, 26, 21, 17, 13, 9, 5, 2, 0, -2, -5, -9, -13, -17, -21, -26, -32, -26, -21, -17, -13, -9, -5, -2, 0, 2, 5, 9, 13, 17, 21, 26, 32];
        for n in [4usize, 8, 16, 32] {
            let mut dst = vec![0u8; 64 * 32];
            let mut row = Vec::new();
            for (name, t) in [("scalar", &s), ("avx", &avx), ("avx2", &d)] {
                let reps = 20_000 / n;
                let t0 = std::time::Instant::now();
                let mut refs = refs.clone();
                let src = refs.clone();
                for _ in 0..reps {
                    for (m, &angle) in angles.iter().enumerate() {
                        // As `predict_prepared` does before every call: the
                        // main side and the corner rewritten, so the
                        // kernel's loads meet fresh, narrower stores.
                        refs[n] = src[n];
                        refs[n + 1..=2 * n].copy_from_slice(&src[n + 1..=2 * n]);
                        (t.intra_angular)(&mut dst, 64, &refs, n, angle, m + 2 < 18);
                    }
                    std::hint::black_box(&mut dst);
                }
                row.push(format!("{name} {:.1}", t0.elapsed().as_nanos() as f64 / (reps * angles.len()) as f64));
            }
            eprintln!("intra_angular {n}x{n}: ns per call {}", row.join(", "));
        }
    }

    #[test]
    fn interp_matches_scalar_u8() {
        let Some(d) = avx2() else { return };
        let s = HevcDsp::<u8>::SCALAR;
        let mut seed = 1u64;
        let stride = 96;
        for trial in 0..3 {
            let src: Vec<u8> = (0..stride * 96)
                .map(|_| match trial {
                    0 => lcg(&mut seed) as u8,
                    1 => [0u8, 255][(lcg(&mut seed) % 2) as usize],
                    _ => (lcg(&mut seed) % 4) as u8 * 85,
                })
                .collect();
            for &(w, h) in &[(2usize, 4usize), (2, 8), (4, 4), (4, 8), (4, 3), (6, 8), (8, 4), (8, 8), (8, 5), (12, 16), (16, 16), (24, 32), (32, 8), (48, 64), (64, 64)] {
                for frac in 1..8 {
                    let mut a = vec![0i16; w * h];
                    let mut b = vec![0i16; w * h];
                    if frac < 4 {
                        (s.qpel_h)(&mut a, &src, stride, w, h, frac, 0);
                        (d.qpel_h)(&mut b, &src, stride, w, h, frac, 0);
                        assert_eq!(a, b, "qpel_h {w}x{h} frac={frac} trial={trial}");
                        (s.qpel_v)(&mut a, &src, stride, w, h, frac, 0);
                        (d.qpel_v)(&mut b, &src, stride, w, h, frac, 0);
                        assert_eq!(a, b, "qpel_v {w}x{h} frac={frac} trial={trial}");
                        let mid: Vec<i16> = (0..stride * 96).map(|_| (lcg(&mut seed) % 30000) as i16 - 15000).collect();
                        (s.qpel_v2)(&mut a, &mid, stride, w, h, frac);
                        (d.qpel_v2)(&mut b, &mid, stride, w, h, frac);
                        assert_eq!(a, b, "qpel_v2 {w}x{h} frac={frac}");
                    }
                    (s.epel_h)(&mut a, &src, stride, w, h, frac, 0);
                    (d.epel_h)(&mut b, &src, stride, w, h, frac, 0);
                    assert_eq!(a, b, "epel_h {w}x{h} frac={frac} trial={trial}");
                    (s.epel_v)(&mut a, &src, stride, w, h, frac, 0);
                    (d.epel_v)(&mut b, &src, stride, w, h, frac, 0);
                    assert_eq!(a, b, "epel_v {w}x{h} frac={frac} trial={trial}");
                    let mid: Vec<i16> = (0..stride * 96).map(|_| (lcg(&mut seed) % 30000) as i16 - 15000).collect();
                    (s.epel_v2)(&mut a, &mid, stride, w, h, frac);
                    (d.epel_v2)(&mut b, &mid, stride, w, h, frac);
                    assert_eq!(a, b, "epel_v2 {w}x{h} frac={frac}");
                }
                let mut a = vec![0i16; w * h];
                let mut b = vec![0i16; w * h];
                (s.qpel_copy)(&mut a, &src, stride, w, h, 6);
                (d.qpel_copy)(&mut b, &src, stride, w, h, 6);
                assert_eq!(a, b, "copy {w}x{h}");
            }
        }
    }

    #[test]
    fn fused_matches_scalar_u8() {
        let Some(d) = avx2() else { return };
        let s = HevcDsp::<u8>::SCALAR;
        let mut seed = 5u64;
        let stride = 96;
        let mut tmp1 = vec![0i16; crate::dsp::hevc::MC_TMP_LEN];
        let mut tmp2 = vec![0i16; crate::dsp::hevc::MC_TMP_LEN];
        let mut checked = 0;
        for trial in 0..2 {
            let src: Vec<u8> = (0..stride * 96).map(|_| if trial == 0 { lcg(&mut seed) as u8 } else { [0u8, 255][(lcg(&mut seed) % 2) as usize] }).collect();
            for &(w, h) in &[(2usize, 4usize), (2, 8), (4, 4), (4, 8), (4, 3), (6, 8), (8, 4), (8, 8), (8, 5), (12, 16), (16, 16), (24, 32), (32, 8), (48, 64), (64, 64)] {
                let other: Vec<i16> = (0..w * h).map(|_| (lcg(&mut seed) % 30000) as i16 - 6000).collect();
                for fx in 0..8 {
                    for fy in 0..8 {
                        for luma in [true, false] {
                            if luma && (fx >= 4 || fy >= 4) {
                                continue;
                            }
                            let dstride = w + 3;
                            let mut d1 = vec![7u8; dstride * h + 8];
                            let mut d2 = d1.clone();
                            let off = 8 * stride + 8;
                            if luma {
                                (s.qpel_uni)(&mut d1, dstride, &src[off..], stride, w, h, fx, fy, &mut tmp1, 8);
                                (d.qpel_uni)(&mut d2, dstride, &src[off..], stride, w, h, fx, fy, &mut tmp2, 8);
                            } else {
                                (s.epel_uni)(&mut d1, dstride, &src[off..], stride, w, h, fx, fy, &mut tmp1, 8);
                                (d.epel_uni)(&mut d2, dstride, &src[off..], stride, w, h, fx, fy, &mut tmp2, 8);
                            }
                            assert_eq!(d1, d2, "uni luma={luma} {w}x{h} fx={fx} fy={fy} trial={trial}");
                            if luma {
                                (s.qpel_bi)(&mut d1, dstride, &src[off..], stride, w, h, fx, fy, &mut tmp1, &other, 8);
                                (d.qpel_bi)(&mut d2, dstride, &src[off..], stride, w, h, fx, fy, &mut tmp2, &other, 8);
                            } else {
                                (s.epel_bi)(&mut d1, dstride, &src[off..], stride, w, h, fx, fy, &mut tmp1, &other, 8);
                                (d.epel_bi)(&mut d2, dstride, &src[off..], stride, w, h, fx, fy, &mut tmp2, &other, 8);
                            }
                            assert_eq!(d1, d2, "bi luma={luma} {w}x{h} fx={fx} fy={fy} trial={trial}");
                            checked += 1;
                        }
                    }
                }
            }
        }
        assert_eq!(checked, 2 * 15 * (16 + 64));
    }

    #[test]
    fn combine_matches_scalar_u8() {
        let Some(d) = avx2() else { return };
        let s = HevcDsp::<u8>::SCALAR;
        let mut seed = 3u64;
        let max = 255;
        for &(w, h) in &[(2usize, 4usize), (4, 4), (6, 8), (8, 8), (12, 16), (16, 8), (24, 4), (32, 32), (64, 64)] {
            for range in [16000i32, 22500] {
                let a: Vec<i16> = (0..w * h).map(|_| ((lcg(&mut seed) % (2 * range as u32)) as i32 - range) as i16).collect();
                let b: Vec<i16> = (0..w * h).map(|_| ((lcg(&mut seed) % (2 * range as u32)) as i32 - range) as i16).collect();
                let stride = w + 5;
                let mut d1 = vec![0u8; stride * h];
                let mut d2 = vec![0u8; stride * h];
                (s.uni)(&mut d1, stride, &a, w, h, 6, max);
                (d.uni)(&mut d2, stride, &a, w, h, 6, max);
                assert_eq!(d1, d2, "uni {w}x{h}");
                (s.bi)(&mut d1, stride, &a, &b, w, h, 7, max);
                (d.bi)(&mut d2, stride, &a, &b, w, h, 7, max);
                assert_eq!(d1, d2, "bi {w}x{h} range={range}");
                for &(log2_wd, wt, o) in &[(6 + 6, 128, 0), (6, 1, 5), (7 + 6, -20, -3), (3 + 6, 255, 127)] {
                    (s.weighted_uni)(&mut d1, stride, &a, w, h, log2_wd, wt, o, max);
                    (d.weighted_uni)(&mut d2, stride, &a, w, h, log2_wd, wt, o, max);
                    assert_eq!(d1, d2, "wuni {w}x{h} {log2_wd} {wt} {o}");
                    (s.weighted_bi)(&mut d1, stride, &a, &b, w, h, log2_wd, wt, 3 - wt, o, -o, max);
                    (d.weighted_bi)(&mut d2, stride, &a, &b, w, h, log2_wd, wt, 3 - wt, o, -o, max);
                    assert_eq!(d1, d2, "wbi {w}x{h}");
                }
            }
            let res: Vec<i16> = (0..w * w).map(|_| (lcg(&mut seed) % 700) as i16 - 350).collect();
            if w == h && w >= 4 && w.is_power_of_two() {
                let stride = w + 5;
                let base: Vec<u8> = (0..stride * h).map(|_| lcg(&mut seed) as u8).collect();
                let mut d1 = base.clone();
                let mut d2 = base.clone();
                (s.add_residual)(&mut d1, stride, &res, w, max);
                (d.add_residual)(&mut d2, stride, &res, w, max);
                assert_eq!(d1, d2, "add_residual {w}");
            }
        }
    }

    #[test]
    fn sao_matches_scalar_u8() {
        let Some(d) = avx2() else { return };
        let s = HevcDsp::<u8>::SCALAR;
        let mut seed = 11u64;
        let stride = 80;
        let max = 255;
        for trial in 0..3 {
            let src: Vec<u8> = (0..stride * 80)
                .map(|_| match trial {
                    0 => lcg(&mut seed) as u8,
                    1 => (lcg(&mut seed) % 3) as u8 + 100,
                    _ => [0u8, 255, 254, 1][(lcg(&mut seed) % 4) as usize],
                })
                .collect();
            for &(w, h) in &[(3usize, 5usize), (8, 8), (16, 16), (31, 17), (33, 9), (64, 64), (72, 3)] {
                let mut table = [0i16; 32];
                let pos = (lcg(&mut seed) % 32) as usize;
                for k in 0..4 {
                    table[(pos + k) & 31] = (lcg(&mut seed) % 15) as i16 - 7;
                }
                let mut d1 = src.clone();
                let mut d2 = src.clone();
                let off = 8 * stride + 8;
                (s.sao_band)(&mut d1[off..], stride, &src[off..], stride, w, h, &table, 3, max);
                (d.sao_band)(&mut d2[off..], stride, &src[off..], stride, w, h, &table, 3, max);
                assert_eq!(d1, d2, "band {w}x{h} trial={trial}");
                let offs: [i16; 5] = [(lcg(&mut seed) % 8) as i16, (lcg(&mut seed) % 8) as i16, 0, -((lcg(&mut seed) % 8) as i16), -((lcg(&mut seed) % 8) as i16)];
                for &(na, nb) in &[(-1isize, 1isize), (-(stride as isize), stride as isize), (-(stride as isize) - 1, stride as isize + 1), (-(stride as isize) + 1, stride as isize - 1)] {
                    let mut d1 = src.clone();
                    let mut d2 = src.clone();
                    (s.sao_edge)(&mut d1, &src, off, stride, w, h, na, nb, &offs, max);
                    (d.sao_edge)(&mut d2, &src, off, stride, w, h, na, nb, &offs, max);
                    assert_eq!(d1, d2, "edge {w}x{h} {na} {nb} trial={trial}");
                }
            }
        }
    }

    #[test]
    fn deblocking_matches_scalar_u8() {
        let Some(d) = avx2() else { return };
        let s = HevcDsp::<u8>::SCALAR;
        let mut seed = 23u64;
        let stride = 40;
        let max = 255;
        for trial in 0..600 {
            let base = lcg(&mut seed) % 256;
            let spread = 1 + lcg(&mut seed) % 16;
            let plane: Vec<u8> = (0..stride * 32).map(|_| (base + lcg(&mut seed) % spread).min(255) as u8).collect();
            let rnd = |seed: &mut u64, n: u32| lcg(seed) % n;
            let v = |seed: &mut u64, n: u32| rnd(seed, n) as i32;
            let beta = [rnd(&mut seed, 3).min(1) as i32 * v(&mut seed, 64), rnd(&mut seed, 3).min(1) as i32 * v(&mut seed, 64)];
            let tc = [rnd(&mut seed, 3).min(1) as i32 * v(&mut seed, 25), rnd(&mut seed, 3).min(1) as i32 * v(&mut seed, 25)];
            let np = [rnd(&mut seed, 5) == 0, rnd(&mut seed, 5) == 0];
            let nq = [rnd(&mut seed, 5) == 0, rnd(&mut seed, 5) == 0];
            let tc4 = [v(&mut seed, 25) * (rnd(&mut seed, 2) as i32), v(&mut seed, 25), 0, v(&mut seed, 25)];
            let np4 = [rnd(&mut seed, 5) == 0, rnd(&mut seed, 5) == 0, false, rnd(&mut seed, 5) == 0];
            let nq4 = [rnd(&mut seed, 5) == 0, false, rnd(&mut seed, 5) == 0, rnd(&mut seed, 5) == 0];
            let off = 8 * stride + 8;
            let mut a = plane.clone();
            let mut b = plane.clone();
            match trial % 4 {
                0 => {
                    (s.deblock_luma_v)(&mut a, off, stride, beta, tc, np, nq, max);
                    (d.deblock_luma_v)(&mut b, off, stride, beta, tc, np, nq, max);
                }
                1 => {
                    (s.deblock_luma_h)(&mut a, off, stride, beta, tc, np, nq, max);
                    (d.deblock_luma_h)(&mut b, off, stride, beta, tc, np, nq, max);
                }
                2 => {
                    (s.deblock_chroma_v)(&mut a, off, stride, tc4, np4, nq4, max);
                    (d.deblock_chroma_v)(&mut b, off, stride, tc4, np4, nq4, max);
                }
                _ => {
                    (s.deblock_chroma_h)(&mut a, off, stride, tc4, np4, nq4, max);
                    (d.deblock_chroma_h)(&mut b, off, stride, tc4, np4, nq4, max);
                }
            }
            assert_eq!(a, b, "hevc u8 deblock kind {} trial {trial} beta {beta:?} tc {tc:?}", trial % 4);
        }
    }
}
