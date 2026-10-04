//! Pixel kernels: interpolation filters, inverse transforms, deblocking and
//! SAO edges — the loops a decoder spends its time in.
//!
//! Every kernel exists as a scalar reference implementation, and the hot ones
//! also as SIMD: on x86-64 a ladder from SSE2 up through SSSE3, SSE4.1, AVX
//! and AVX2, with AVX-512 over the top of AVX2 for the few shapes where
//! 512-bit lanes pay for themselves, and on AArch64 NEON with the dot
//! product extension above it. Which runs is decided once per process
//! by [`Cpu::detect`] and threaded through as function pointers, the way
//! libavcodec's `*dsp_init` tables work, so the decoders never branch on the
//! CPU themselves and the scalar path stays the executable specification the
//! SIMD path is tested against.

pub mod distortion;
pub mod h264;
pub mod h264_enc;
pub mod hevc;
pub mod hevc_enc;
#[doc(hidden)]
pub mod u16_sweep;
// The SIMD modules call `core::arch` intrinsics directly. From Rust 1.87
// (below the MSRV) an intrinsic that takes no raw pointer is safe to call
// inside a function whose own `#[target_feature]` enables what it needs, so
// those calls sit outside `unsafe` blocks and no module here allows
// `unused_unsafe`: a redundant block is a warning. The blocks that remain
// hold something unsafe on any toolchain — a load or store through a raw
// pointer, pointer arithmetic, `ptr::read_unaligned` / `write_unaligned` /
// `copy_nonoverlapping`, or a call to one of the `unsafe fn` kernels.
//
// Two edges of that rule decide what stays. A feature the *target* enables
// does not count, only the caller's attribute does: NEON is baseline on
// AArch64, yet a NEON helper with no `#[target_feature]` of its own (such as
// `h264_neon`'s `round5`) still needs its block. And on wasm32 rustc treats
// every call to a `#[target_feature]` function as safe, so the `simd128`
// modules never had redundant blocks to allow.
#[cfg(target_arch = "aarch64")]
pub(crate) mod distortion_neon;
#[cfg(target_arch = "aarch64")]
pub(crate) mod distortion_neon_u16;
#[cfg(target_arch = "x86_64")]
pub(crate) mod distortion_x86;
#[cfg(target_arch = "x86_64")]
pub(crate) mod distortion_x86_u16;
#[cfg(target_arch = "x86_64")]
pub(crate) mod h264_avx2;
#[cfg(target_arch = "x86_64")]
pub(crate) mod h264_avx2_u16;
#[cfg(target_arch = "x86_64")]
pub(crate) mod h264_enc_x86;
#[cfg(target_arch = "aarch64")]
pub(crate) mod h264_neon;
#[cfg(target_arch = "aarch64")]
pub(crate) mod h264_neon_u16;
#[cfg(target_arch = "wasm32")]
pub(crate) mod h264_wasm128;
#[cfg(target_arch = "wasm32")]
pub(crate) mod h264_wasm128_u16;
#[cfg(target_arch = "x86_64")]
pub(crate) mod h264_x86_128;
#[cfg(target_arch = "x86_64")]
pub(crate) mod h264_x86_128_u16;
#[cfg(target_arch = "x86_64")]
pub(crate) mod hevc_avx2;
#[cfg(target_arch = "x86_64")]
pub(crate) mod hevc_avx2_u8;
#[cfg(target_arch = "x86_64")]
pub(crate) mod hevc_avx512;
#[cfg(target_arch = "x86_64")]
pub(crate) mod hevc_avx512_u8;
#[cfg(target_arch = "x86_64")]
pub(crate) mod hevc_enc_x86;
#[cfg(target_arch = "aarch64")]
pub(crate) mod hevc_neon;
#[cfg(target_arch = "aarch64")]
pub(crate) mod hevc_neon_u8;
#[cfg(target_arch = "wasm32")]
pub(crate) mod hevc_wasm128;
#[cfg(target_arch = "x86_64")]
pub(crate) mod hevc_x86_128;
#[cfg(target_arch = "aarch64")]
pub(crate) mod neon_dotprod;
#[cfg(target_arch = "x86_64")]
pub(crate) mod sao_x86;
#[cfg(target_arch = "x86_64")]
pub(crate) mod x86_compat;
// The encode-only tiers beyond x86: the same kernels as `distortion_x86`
// and `hevc_enc_x86`, on NEON and on wasm `simd128`.
#[cfg(target_arch = "wasm32")]
pub(crate) mod distortion_wasm128;
#[cfg(target_arch = "wasm32")]
pub(crate) mod distortion_wasm128_u16;
#[cfg(target_arch = "aarch64")]
pub(crate) mod h264_enc_neon;
#[cfg(target_arch = "wasm32")]
pub(crate) mod h264_enc_wasm128;
#[cfg(target_arch = "aarch64")]
pub(crate) mod hevc_enc_neon;
#[cfg(target_arch = "wasm32")]
pub(crate) mod hevc_enc_wasm128;

/// Whether `H26X_ENC_NO_SIMD` asks the encode-only kernel table `table`
/// (`distortion`, `h264_enc` or `hevc_enc`) to keep its scalar references
/// while the decoder-shared tables take the CPU's rungs as usual. `1`
/// names all three; a comma-separated list names some.
///
/// This exists for one purpose — measuring what the encode-side kernels
/// are worth, one binary, same run of everything else. `H26X_NO_SIMD`
/// cannot answer that: it also strips the interpolation, inverse
/// transforms and loop filters the encoders share with the decoders, so
/// the difference it shows is mostly theirs. Naming one table isolates
/// one step of the work. Read at table construction, which is once per
/// encoder (or per picture in H.265), not per kernel.
pub fn enc_simd_disabled(table: &str) -> bool {
    match std::env::var("H26X_ENC_NO_SIMD") {
        Ok(v) => v == "1" || v == "true" || v.split(',').any(|t| t.trim() == table),
        Err(_) => false,
    }
}

/// What the running CPU can do, detected once.
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub struct Cpu {
    /// x86-64 with AVX2 (implies AVX / SSE4.1 / SSSE3).
    pub avx2: bool,
    /// x86-64 with AVX-512 F + BW + VL: 512-bit vectors, byte and word
    /// lanes, and masked stores narrower than the vector. Masked *loads* are
    /// a different matter on Zen 5 and cost several times a plain one: a
    /// chroma kernel that read its nine bytes with one `vmovdqu8` came out
    /// twice as slow as AVX2, and two plain loads and an unpack made the same
    /// kernel 1.5x faster instead. Unlike the rungs
    /// below it this one is a *supplement*, not a replacement — the AVX-512
    /// modules install over a finished AVX2 table and leave every kernel and
    /// block shape they do not carry alone.
    pub avx512: bool,
    /// x86-64 with AVX-512 VNNI (`vpdpwssd`). Detected, but no kernel uses
    /// it: it folds the `vpaddd` after `pmaddwd` into the multiply, which is
    /// one instruction saved of four in every accumulate loop here — and it
    /// measured *slower*, because it also serialises them. `pmaddwd` and
    /// `vpaddd` let the products issue in parallel and chain only the adds;
    /// `vpdpwssd` puts the accumulator in the dependency chain of every
    /// multiply. The 32-point transform, which accumulates up to sixteen
    /// coefficient pairs into one register, lost 5-9% to it; the eight-tap
    /// vertical filter, chaining only four, came out level. Worth revisiting
    /// with several accumulators to break the chain, which would want the
    /// non-VNNI bodies restructured the same way.
    pub avx512vnni: bool,
    /// x86-64 with AVX: the 128-bit kernels, VEX-encoded.
    pub avx: bool,
    /// x86-64 with SSE4.1 (`pblendvb`, `pmovzx`, `pminsd` / `pmaxsd`, `ptest`).
    pub sse41: bool,
    /// x86-64 with SSSE3 (`pmaddubsw`, `pshufb`, `pabsw` / `pabsd`).
    pub ssse3: bool,
    /// x86-64 with SSE2 — baseline on every x86-64 CPU, so on this
    /// architecture the scalar kernels are a reference, never a fallback.
    pub sse2: bool,
    /// wasm32 with the `simd128` proposal.
    ///
    /// Not detected the way the others are, because there is nothing to
    /// detect: `simd128` is a compile-time target feature, so a module either
    /// was built with it or was not. It is a field on `Cpu` anyway so that
    /// `rung` can name it and `H26X_NO_SIMD=1` can still take it away, which
    /// is what makes the scalar reference reachable for comparison.
    pub simd128: bool,
    /// AArch64 NEON (baseline on every AArch64 CPU).
    pub neon: bool,
    /// AArch64 with the ARMv8.2-A dot product extension (`sdot` / `udot`):
    /// four 8-bit products summed into a 32-bit lane, which is the shape of
    /// the byte-tap interpolation filters. Cortex-A75 and later, Apple A11
    /// and later — not an exotic target.
    pub dotprod: bool,
    /// AArch64 with the ARMv8.6-A 8-bit matrix multiply extension (`usdot` /
    /// `usmmla`). Detected, but no kernel uses it yet: `neon_dotprod`'s
    /// module documentation says why it does not pay on these filters.
    pub i8mm: bool,
}

impl Cpu {
    /// Detect the running CPU's SIMD extensions.
    pub fn detect() -> Self {
        #[cfg(target_arch = "x86_64")]
        {
            let avx2 = std::is_x86_feature_detected!("avx2");
            let avx = std::is_x86_feature_detected!("avx");
            let sse41 = std::is_x86_feature_detected!("sse4.1");
            let ssse3 = std::is_x86_feature_detected!("ssse3");
            // Guaranteed by the target, but ask anyway rather than assert it.
            let sse2 = std::is_x86_feature_detected!("sse2");
            // BW for the byte and word lanes the sample arithmetic runs in,
            // VL for the masked stores that write a partial row without a
            // branch. F alone would leave both out.
            let avx512 = avx2
                && std::is_x86_feature_detected!("avx512f")
                && std::is_x86_feature_detected!("avx512bw")
                && std::is_x86_feature_detected!("avx512vl");
            let avx512vnni = avx512 && std::is_x86_feature_detected!("avx512vnni");
            return Self {
                avx2,
                avx512,
                avx512vnni,
                avx,
                sse41,
                ssse3,
                sse2,
                ..Self::SCALAR
            };
        }
        #[cfg(target_arch = "wasm32")]
        {
            return Self {
                simd128: cfg!(target_feature = "simd128"),
                ..Self::SCALAR
            };
        }
        #[cfg(target_arch = "aarch64")]
        {
            let dotprod = std::arch::is_aarch64_feature_detected!("dotprod");
            let i8mm = std::arch::is_aarch64_feature_detected!("i8mm");
            return Self {
                neon: true,
                dotprod,
                i8mm,
                ..Self::SCALAR
            };
        }
        #[allow(unreachable_code)]
        Self::SCALAR
    }

    /// Scalar only — the reference paths. What the SIMD kernels are checked
    /// against, and what a `H26X_NO_SIMD=1` environment asks for.
    pub const SCALAR: Self = Self {
        avx2: false,
        avx512: false,
        avx512vnni: false,
        avx: false,
        sse41: false,
        ssse3: false,
        sse2: false,
        simd128: false,
        neon: false,
        dotprod: false,
        i8mm: false,
    };

    /// The name of the widest rung this `Cpu` selects, for reporting.
    ///
    /// Which rung a machine takes decides its speed by more than a factor of
    /// two, so a user who cannot ask which one they got cannot make sense of
    /// a measurement. `h26xdec --rung` prints this.
    pub fn rung(&self) -> &'static str {
        if self.simd128 {
            "SIMD128"
        } else if self.avx512 {
            "AVX-512"
        } else if self.avx2 {
            "AVX2"
        } else if self.avx {
            "AVX (VEX-128)"
        } else if self.sse41 {
            "SSE4.1"
        } else if self.ssse3 {
            "SSSE3"
        } else if self.sse2 {
            "SSE2"
        } else if self.dotprod {
            "NEON + DotProd"
        } else if self.neon {
            "NEON"
        } else {
            "scalar"
        }
    }

    /// [`Self::detect`], with what it found capped by the environment.
    ///
    /// `H26X_NO_SIMD=1` asks for the scalar reference paths. `H26X_MAX_SIMD`
    /// caps the x86 install level — `avx512` (no cap), `avx2`, `avx`,
    /// `sse41`, `ssse3`, `sse2` or `none` — so every rung of the ladder,
    /// including the AVX-512 kernels layered over AVX2, can be exercised for
    /// bit-exactness on a machine whose CPU would otherwise always take the
    /// top one. An unrecognised value is ignored rather than silently
    /// downgrading.
    pub fn detect_honouring_env() -> Self {
        if std::env::var_os("H26X_NO_SIMD").is_some_and(|v| v == "1" || v == "true") {
            return Self::SCALAR;
        }
        let mut cpu = Self::detect();
        // Each arm falls through the ones above it: capping at `ssse3` also
        // clears sse41, avx and avx2.
        match std::env::var("H26X_MAX_SIMD").as_deref() {
            Ok("none") | Ok("scalar") => cpu = Self::SCALAR,
            Ok("sse2") => {
                cpu.avx512 = false;
                cpu.avx512vnni = false;
                cpu.avx2 = false;
                cpu.avx = false;
                cpu.sse41 = false;
                cpu.ssse3 = false;
            }
            Ok("ssse3") => {
                cpu.avx512 = false;
                cpu.avx512vnni = false;
                cpu.avx2 = false;
                cpu.avx = false;
                cpu.sse41 = false;
            }
            Ok("sse41") | Ok("sse4.1") => {
                cpu.avx512 = false;
                cpu.avx512vnni = false;
                cpu.avx2 = false;
                cpu.avx = false;
            }
            Ok("avx") => {
                cpu.avx512 = false;
                cpu.avx512vnni = false;
                cpu.avx2 = false;
            }
            Ok("avx2") => {
                cpu.avx512 = false;
                cpu.avx512vnni = false;
            }
            // The top of the ladder: recognised so that it is documented and
            // so `verify.sh` can name every rung uniformly, but there is
            // nothing above it to switch off.
            Ok("avx512") => {}
            // AArch64: cap at baseline NEON.
            Ok("neon") => {
                cpu.dotprod = false;
                cpu.i8mm = false;
            }
            _ => {}
        }
        cpu
    }
}
