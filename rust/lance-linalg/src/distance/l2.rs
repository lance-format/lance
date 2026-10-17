// SPDX-License-Identifier: Apache-2.0
// SPDX-FileCopyrightText: Copyright The Lance Authors

//! L2 (Euclidean) distance.
//!

use std::iter::Sum;
use std::ops::AddAssign;
use std::sync::Arc;

use crate::{Error, Result};
use arrow_array::{
    Array, FixedSizeListArray, Float32Array,
    cast::AsArray,
    types::{Float16Type, Float32Type, Float64Type, Int8Type},
};
use arrow_schema::DataType;
use half::{bf16, f16};
use lance_arrow::{ArrowFloatType, FixedSizeListArrayExt, FloatArray};
use lance_core::deepsize::DeepSizeOf;
use num_traits::{AsPrimitive, Num};

use crate::distance::{
    BatchKernel, PairKernel, U8_U32_ACCUMULATOR_MAX_LEN, assert_batch_output_layout,
    assert_equal_lengths, int8_query_to_f32,
};

/// Calculate the L2 distance between two vectors.
///
pub trait L2: Num {
    /// Calculate the L2 distance between two vectors.
    fn l2(x: &[Self], y: &[Self]) -> f32;

    /// Writes the L2 distance from `x` to each `dimension`-sized vector in
    /// `batch` into the matching element of `output`.
    ///
    /// The default calls [`L2::l2`] per vector. `f32` overrides it with one
    /// batch kernel call, so the SIMD tier is chosen once for the whole batch
    /// instead of once per vector.
    ///
    /// # Panics
    ///
    /// Panics if `x.len() != dimension`, if `batch.len()` is not a multiple of
    /// `dimension`, or if `output.len() != batch.len() / dimension`.
    fn l2_batch_into(x: &[Self], batch: &[Self], dimension: usize, output: &mut [f32]) {
        assert_batch_output_layout(x.len(), batch.len(), dimension, output.len());
        for (distance, y) in output.iter_mut().zip(batch.chunks_exact(dimension)) {
            *distance = Self::l2(x, y);
        }
    }
}

#[inline]
pub fn l2<T: L2>(from: &[T], to: &[T]) -> f32 {
    T::l2(from, to)
}

/// L2 distance between two f32 slices, dispatched to the widest SIMD backend
/// available at runtime.
///
/// On x86_64 with AVX-512 this uses 16-wide f32 lanes; otherwise it falls back
/// to [`l2`], whose x86_64 implementation selects the best runtime-supported
/// kernel. This entry point gives hot-path callers such as the in-memory HNSW
/// index an explicit f32 API.
#[inline]
pub fn l2_f32(x: &[f32], y: &[f32]) -> f32 {
    f32::l2(x, y)
}

/// Calculate L2 distance between two uint8 slices.
#[inline]
pub fn l2_distance_uint_scalar(key: &[u8], target: &[u8]) -> f32 {
    assert_equal_lengths(key.len(), target.len());
    // Keep the common path on a u32 accumulator so LLVM can auto-vectorize it
    // efficiently. Longer inputs are widened between overflow-safe chunks.
    if key.len() <= U8_U32_ACCUMULATOR_MAX_LEN {
        return key
            .iter()
            .zip(target.iter())
            .map(|(&x, &y)| (x.abs_diff(y) as u32).pow(2))
            .sum::<u32>() as f32;
    }

    key.chunks(U8_U32_ACCUMULATOR_MAX_LEN)
        .zip(target.chunks(U8_U32_ACCUMULATOR_MAX_LEN))
        .map(|(key, target)| {
            key.iter()
                .zip(target.iter())
                .map(|(&x, &y)| (x.abs_diff(y) as u32).pow(2))
                .sum::<u32>() as u64
        })
        .sum::<u64>() as f32
}

/// Calculate the L2 distance between two vectors, using scalar operations.
///
/// It relies on LLVM for auto-vectorization and unrolling.
///
/// This is pub for test/benchmark only. use [l2] instead.
#[inline(always)]
pub fn l2_scalar<
    T: AsPrimitive<Output>,
    Output: Num + Copy + Sum + AddAssign + 'static,
    const LANES: usize,
>(
    from: &[T],
    to: &[T],
) -> Output {
    assert_equal_lengths(from.len(), to.len());
    let (x_chunks, x_remainder) = from.as_chunks::<LANES>();
    let (y_chunks, y_remainder) = to.as_chunks::<LANES>();

    let s = if !x_remainder.is_empty() {
        x_remainder
            .iter()
            .zip(y_remainder)
            .map(|(&x, &y)| {
                let diff = x.as_() - y.as_();
                diff * diff
            })
            .sum::<Output>()
    } else {
        Output::zero()
    };

    let mut sums = [Output::zero(); LANES];
    for (x, y) in x_chunks.iter().zip(y_chunks) {
        for i in 0..LANES {
            let diff = x[i].as_() - y[i].as_();
            sums[i] += diff * diff;
        }
    }

    s + sums.iter().copied().sum()
}

impl L2 for u8 {
    #[inline]
    fn l2(x: &[Self], y: &[Self]) -> f32 {
        assert_equal_lengths(x.len(), y.len());
        super::l2_u8::l2_u8_u64(x, y) as f32
    }
}

impl L2 for bf16 {
    #[inline]
    fn l2(x: &[Self], y: &[Self]) -> f32 {
        assert_equal_lengths(x.len(), y.len());
        L2_BF16.get().call(x, y)
    }
}

impl L2 for f16 {
    #[inline]
    fn l2(x: &[Self], y: &[Self]) -> f32 {
        assert_equal_lengths(x.len(), y.len());
        L2_F16.get().call(x, y)
    }
}

lance_core::dispatch! {
    static L2_F16: Dispatch<PairKernel<f16>> = &[
        #[cfg(all(kernel_support = "avx512_f16", target_arch = "x86_64"))]
        half_c::L2_F16_AVX512,
        #[cfg(all(kernel_support = "half", target_arch = "x86_64"))]
        half_c::L2_F16_AVX2,
        #[cfg(all(kernel_support = "half", target_arch = "aarch64"))]
        half_c::L2_F16_NEON,
        #[cfg(all(kernel_support = "half", target_arch = "loongarch64"))]
        half_c::L2_F16_LASX,
        #[cfg(all(kernel_support = "half", target_arch = "loongarch64"))]
        half_c::L2_F16_LSX,
        L2_F16_SCALAR,
    ];
}

lance_core::dispatch! {
    static L2_BF16: Dispatch<PairKernel<bf16>> = &[
        #[cfg(all(kernel_support = "avx512_bf16", target_arch = "x86_64"))]
        half_c::L2_BF16_AVX512,
        #[cfg(all(kernel_support = "half", target_arch = "x86_64"))]
        half_c::L2_BF16_AVX2,
        #[cfg(all(kernel_support = "half", target_arch = "aarch64"))]
        half_c::L2_BF16_NEON,
        #[cfg(all(kernel_support = "half", target_arch = "loongarch64"))]
        half_c::L2_BF16_LASX,
        #[cfg(all(kernel_support = "half", target_arch = "loongarch64"))]
        half_c::L2_BF16_LSX,
        L2_BF16_SCALAR,
    ];
}

lance_core::target_kernel! {
    #[target_features()]
    #[candidate(L2_F16_SCALAR: PairKernel<f16>)]
    fn l2_f16_scalar(x: &[f16], y: &[f16]) -> f32 {
        l2_scalar::<f16, f32, 16>(x, y)
    }
}

lance_core::target_kernel! {
    #[target_features()]
    #[candidate(L2_BF16_SCALAR: PairKernel<bf16>)]
    fn l2_bf16_scalar(x: &[bf16], y: &[bf16]) -> f32 {
        l2_scalar::<bf16, f32, 16>(x, y)
    }
}

/// The `l2_f16` and `l2_bf16` functions in f16.c and bf16.c. build.rs compiles
/// each file once per SIMD level, suffixing the symbols with the level.
#[cfg(kernel_support = "half")]
mod half_c {
    use half::{bf16, f16};

    use crate::distance::PairKernel;

    mod ffi {
        use half::{bf16, f16};

        unsafe extern "C" {
            #[cfg(all(kernel_support = "avx512_f16", target_arch = "x86_64"))]
            pub fn l2_f16_avx512(ptr1: *const f16, ptr2: *const f16, len: u32) -> f32;
            #[cfg(target_arch = "x86_64")]
            pub fn l2_f16_avx2(ptr1: *const f16, ptr2: *const f16, len: u32) -> f32;
            #[cfg(target_arch = "aarch64")]
            pub fn l2_f16_neon(ptr1: *const f16, ptr2: *const f16, len: u32) -> f32;
            #[cfg(target_arch = "loongarch64")]
            pub fn l2_f16_lasx(ptr1: *const f16, ptr2: *const f16, len: u32) -> f32;
            #[cfg(target_arch = "loongarch64")]
            pub fn l2_f16_lsx(ptr1: *const f16, ptr2: *const f16, len: u32) -> f32;

            #[cfg(all(kernel_support = "avx512_bf16", target_arch = "x86_64"))]
            pub fn l2_bf16_avx512(ptr1: *const bf16, ptr2: *const bf16, len: u32) -> f32;
            #[cfg(target_arch = "x86_64")]
            pub fn l2_bf16_avx2(ptr1: *const bf16, ptr2: *const bf16, len: u32) -> f32;
            #[cfg(target_arch = "aarch64")]
            pub fn l2_bf16_neon(ptr1: *const bf16, ptr2: *const bf16, len: u32) -> f32;
            #[cfg(target_arch = "loongarch64")]
            pub fn l2_bf16_lasx(ptr1: *const bf16, ptr2: *const bf16, len: u32) -> f32;
            #[cfg(target_arch = "loongarch64")]
            pub fn l2_bf16_lsx(ptr1: *const bf16, ptr2: *const bf16, len: u32) -> f32;
        }
    }

    half_c_kernels! {
        fn (x: &[f16], y: &[f16]) -> f32 => (x.as_ptr(), y.as_ptr(), x.len().min(y.len()) as u32);
        #[cfg(all(kernel_support = "avx512_f16", target_arch = "x86_64"))]
        L2_F16_AVX512: PairKernel<f16> = l2_f16_avx512("avx512fp16");
        #[cfg(target_arch = "x86_64")]
        L2_F16_AVX2: PairKernel<f16> = l2_f16_avx2("avx2", "fma", "f16c", "bmi1", "bmi2");
        #[cfg(target_arch = "aarch64")]
        L2_F16_NEON: PairKernel<f16> = l2_f16_neon("neon", "fp16");
        #[cfg(target_arch = "loongarch64")]
        L2_F16_LASX: PairKernel<f16> = l2_f16_lasx("lasx");
        #[cfg(target_arch = "loongarch64")]
        L2_F16_LSX: PairKernel<f16> = l2_f16_lsx("lsx");
    }

    half_c_kernels! {
        fn (x: &[bf16], y: &[bf16]) -> f32 => (x.as_ptr(), y.as_ptr(), x.len().min(y.len()) as u32);
        #[cfg(all(kernel_support = "avx512_bf16", target_arch = "x86_64"))]
        L2_BF16_AVX512: PairKernel<bf16> = l2_bf16_avx512("avx512fp16", "avx512bf16");
        #[cfg(target_arch = "x86_64")]
        L2_BF16_AVX2: PairKernel<bf16> = l2_bf16_avx2("avx2", "fma", "f16c", "bmi1", "bmi2");
        #[cfg(target_arch = "aarch64")]
        L2_BF16_NEON: PairKernel<bf16> = l2_bf16_neon("neon", "fp16");
        #[cfg(target_arch = "loongarch64")]
        L2_BF16_LASX: PairKernel<bf16> = l2_bf16_lasx("lasx");
        #[cfg(target_arch = "loongarch64")]
        L2_BF16_LSX: PairKernel<bf16> = l2_bf16_lsx("lsx");
    }

    // Each candidate must require what build.rs compiled its object for.
    #[cfg(all(test, target_arch = "x86_64"))]
    const _: () = {
        use crate::distance::half_c_objects::{HASWELL, is};
        assert!(is(L2_F16_AVX2.features(), HASWELL));
        assert!(is(L2_BF16_AVX2.features(), HASWELL));
    };
    #[cfg(all(test, target_arch = "x86_64", kernel_support = "avx512_f16"))]
    const _: () = {
        use crate::distance::half_c_objects::{SAPPHIRE_RAPIDS_F16, is};
        assert!(is(L2_F16_AVX512.features(), SAPPHIRE_RAPIDS_F16));
    };
    #[cfg(all(test, target_arch = "x86_64", kernel_support = "avx512_bf16"))]
    const _: () = {
        use crate::distance::half_c_objects::{SAPPHIRE_RAPIDS_BF16, is};
        assert!(is(L2_BF16_AVX512.features(), SAPPHIRE_RAPIDS_BF16));
    };
    #[cfg(all(test, target_arch = "aarch64"))]
    const _: () = {
        use crate::distance::half_c_objects::{ARMV8_2_FP16, is};
        assert!(is(L2_F16_NEON.features(), ARMV8_2_FP16));
        assert!(is(L2_BF16_NEON.features(), ARMV8_2_FP16));
    };
    #[cfg(all(test, target_arch = "loongarch64"))]
    const _: () = {
        use crate::distance::half_c_objects::{LASX, LSX, is};
        assert!(is(L2_F16_LASX.features(), LASX));
        assert!(is(L2_BF16_LASX.features(), LASX));
        assert!(is(L2_F16_LSX.features(), LSX));
        assert!(is(L2_BF16_LSX.features(), LSX));
    };
}

impl L2 for f32 {
    #[inline]
    fn l2(x: &[Self], y: &[Self]) -> f32 {
        assert_equal_lengths(x.len(), y.len());
        L2_F32.get().call(x, y)
    }

    fn l2_batch_into(x: &[Self], batch: &[Self], dimension: usize, output: &mut [f32]) {
        assert_batch_output_layout(x.len(), batch.len(), dimension, output.len());
        L2_F32_BATCH.get().call(x, batch, dimension, output);
    }
}

lance_core::dispatch! {
    static L2_F32: Dispatch<PairKernel> = {
        #[cfg(target_arch = "x86_64")]
        {
            &[
                x86::L2_F32_AVX512,
                x86::L2_F32_AVX_FMA,
                x86::L2_F32_AVX,
                L2_F32_SCALAR,
            ]
        }
        #[cfg(not(target_arch = "x86_64"))]
        {
            &[L2_F32_SCALAR]
        }
    };
}

lance_core::dispatch! {
    /// There is no AVX-512 candidate: the AVX+FMA kernel is the best one so
    /// that Haswell-baseline builds select it at compile time, with no
    /// per-batch dispatch at the 8-wide PQ dimension. Its dimension-dependent
    /// choice mirrors what those builds have always computed.
    static L2_F32_BATCH: Dispatch<BatchKernel> = {
        #[cfg(target_arch = "x86_64")]
        {
            &[
                x86::L2_F32_BATCH_AVX_FMA,
                x86::L2_F32_BATCH_AVX,
                L2_F32_BATCH_SCALAR,
            ]
        }
        #[cfg(not(target_arch = "x86_64"))]
        {
            &[L2_F32_BATCH_SCALAR]
        }
    };
}

lance_core::target_kernel! {
    #[target_features()]
    #[candidate(L2_F32_SCALAR: PairKernel)]
    /// Portable L2 distance for f32, relying on LLVM to auto-vectorize it.
    #[inline]
    fn l2_f32_scalar(x: &[f32], y: &[f32]) -> f32 {
        // Below one 16-lane chunk (e.g. dimension-8 PQ sub-vectors) the
        // 16-lane kernel is all scalar remainder: a serial add chain whose
        // speed swings with code layout. 8 lanes vectorizes it.
        if x.len() < 16 {
            return l2_scalar::<f32, f32, 8>(x, y);
        }
        // 16 = 512 (avx512) / 8 bits / 4 (sizeof(f32))
        // See https://github.com/lance-format/lance/pull/2450.
        l2_scalar::<f32, f32, 16>(x, y)
    }
}

lance_core::target_kernel! {
    #[target_features()]
    #[candidate(L2_F32_BATCH_SCALAR: BatchKernel)]
    #[inline]
    fn l2_batch_f32_scalar(x: &[f32], batch: &[f32], dimension: usize, output: &mut [f32]) {
        for (distance, y) in output.iter_mut().zip(batch.chunks_exact(dimension)) {
            *distance = l2_f32_scalar(x, y);
        }
    }
}

impl L2 for f64 {
    #[inline]
    fn l2(x: &[Self], y: &[Self]) -> f32 {
        assert_equal_lengths(x.len(), y.len());
        L2_F64.get().call(x, y)
    }
}

lance_core::dispatch! {
    static L2_F64: Dispatch<PairKernel<f64>> = {
        #[cfg(target_arch = "x86_64")]
        {
            &[
                x86::L2_F64_AVX512,
                x86::L2_F64_AVX_FMA,
                x86::L2_F64_AVX,
                L2_F64_PORTABLE,
            ]
        }
        #[cfg(not(target_arch = "x86_64"))]
        {
            &[L2_F64_PORTABLE]
        }
    };
}

#[cfg(target_arch = "x86_64")]
lance_core::target_kernel! {
    #[target_features()]
    #[candidate(L2_F64_PORTABLE: PairKernel<f64>)]
    #[inline]
    fn l2_f64_portable(x: &[f64], y: &[f64]) -> f32 {
        x.iter()
            .zip(y.iter())
            .map(|(&a, &b)| {
                let diff = a - b;
                diff * diff
            })
            .sum::<f64>() as f32
    }
}

#[cfg(target_arch = "x86_64")]
mod x86 {
    use std::arch::x86_64::*;

    use crate::distance::{BatchKernel, PairKernel};
    use crate::simd::f64::{f64x4, f64x8};
    use crate::simd::x86::hsum256_ps;
    use crate::simd::{FloatSimd, SIMD};

    lance_core::target_kernel! {
        #[target_features("avx", "fma")]
        #[candidate(pub(super) L2_F32_BATCH_AVX_FMA: BatchKernel)]
        /// Up to 16 dimensions the scalar kernel's 16-lane chunking degenerates
        /// to its remainder loop, so the explicit AVX kernel wins; above that
        /// the auto-vectorized scalar kernel is as good or better.
        pub(super) fn l2_batch_f32_avx_fma(
            x: &[f32],
            batch: &[f32],
            dimension: usize,
            output: &mut [f32],
        ) {
            if dimension == 8
                && let Ok(key) = <&[f32; 8]>::try_from(x)
            {
                let key = unsafe { _mm256_loadu_ps(key.as_ptr()) };
                for (distance, y) in output.iter_mut().zip(batch.as_chunks::<8>().0) {
                    let diff = _mm256_sub_ps(key, unsafe { _mm256_loadu_ps(y.as_ptr()) });
                    *distance = unsafe { hsum256_ps(_mm256_mul_ps(diff, diff)) };
                }
            } else if dimension == 16
                && let Ok(key) = <&[f32; 16]>::try_from(x)
            {
                // Same sums as `l2_f32_avx_fma`, whose first FMA adds to zero,
                // with the key loaded once per batch.
                let (key_lo, key_hi) =
                    unsafe { (_mm256_loadu_ps(key.as_ptr()), _mm256_loadu_ps(key.as_ptr().add(8))) };
                for (distance, y) in output.iter_mut().zip(batch.as_chunks::<16>().0) {
                    let (y_lo, y_hi) =
                        unsafe { (_mm256_loadu_ps(y.as_ptr()), _mm256_loadu_ps(y.as_ptr().add(8))) };
                    let (diff_lo, diff_hi) = (_mm256_sub_ps(key_lo, y_lo), _mm256_sub_ps(key_hi, y_hi));
                    let sum = _mm256_fmadd_ps(diff_hi, diff_hi, _mm256_mul_ps(diff_lo, diff_lo));
                    *distance = unsafe { hsum256_ps(sum) };
                }
            } else if dimension <= 16 {
                for (distance, y) in output.iter_mut().zip(batch.chunks_exact(dimension)) {
                    *distance = l2_f32_avx_fma(x, y);
                }
            } else {
                for (distance, y) in output.iter_mut().zip(batch.chunks_exact(dimension)) {
                    *distance = super::l2_f32_scalar(x, y);
                }
            }
        }
    }

    lance_core::target_kernel! {
        #[target_features("avx")]
        #[candidate(pub(super) L2_F32_BATCH_AVX: BatchKernel)]
        pub(super) fn l2_batch_f32_avx(
            x: &[f32],
            batch: &[f32],
            dimension: usize,
            output: &mut [f32],
        ) {
            if dimension == 8
                && let Ok(key) = <&[f32; 8]>::try_from(x)
            {
                let key = unsafe { _mm256_loadu_ps(key.as_ptr()) };
                for (distance, y) in output.iter_mut().zip(batch.as_chunks::<8>().0) {
                    let diff = _mm256_sub_ps(key, unsafe { _mm256_loadu_ps(y.as_ptr()) });
                    *distance = unsafe { hsum256_ps(_mm256_mul_ps(diff, diff)) };
                }
            } else {
                for (distance, y) in output.iter_mut().zip(batch.chunks_exact(dimension)) {
                    *distance = l2_f32_avx(x, y);
                }
            }
        }
    }

    lance_core::target_kernel! {
        #[target_features("avx512f")]
        #[candidate(pub(super) L2_F64_AVX512: PairKernel<f64>)]
        /// 8-wide `__m512d` with `vsubpd` + `vfmadd231pd` per iteration.
        #[inline]
        pub(super) fn l2_f64_avx512(x: &[f64], y: &[f64]) -> f32 {
            // See `l2_f32_avx512` for `min`.
            let dim = x.len().min(y.len());
            let unrolled_len = dim / 8 * 8;

            let mut acc = _mm512_setzero_pd();
            for i in (0..unrolled_len).step_by(8) {
                // SAFETY: `i + 8 <= dim`, which is in bounds for both slices.
                let (a, b) = unsafe {
                    (
                        _mm512_loadu_pd(x.as_ptr().add(i)),
                        _mm512_loadu_pd(y.as_ptr().add(i)),
                    )
                };
                let diff = _mm512_sub_pd(a, b);
                acc = _mm512_fmadd_pd(diff, diff, acc);
            }

            let tail: f64 = x[unrolled_len..]
                .iter()
                .zip(y[unrolled_len..].iter())
                .map(|(&a, &b)| {
                    let diff = a - b;
                    diff * diff
                })
                .sum();

            (_mm512_reduce_add_pd(acc) + tail) as f32
        }
    }

    lance_core::target_kernel! {
        #[target_features("avx", "fma")]
        #[candidate(pub(super) L2_F64_AVX_FMA: PairKernel<f64>)]
        /// Covers both AVX+FMA and AVX2 hosts (body uses no AVX2-specific intrinsics).
        #[inline]
        pub(super) fn l2_f64_avx_fma(x: &[f64], y: &[f64]) -> f32 {
            // See `l2_f32_avx512` for `min`.
            let dim = x.len().min(y.len());
            let unrolled_len = dim / 8 * 8;

            let mut acc8 = f64x8::zeros();
            for i in (0..unrolled_len).step_by(8) {
                // SAFETY: `i + 8 <= dim`, which is in bounds for both slices.
                let (a, b) = unsafe {
                    (
                        f64x8::load_unaligned(x.as_ptr().add(i)),
                        f64x8::load_unaligned(y.as_ptr().add(i)),
                    )
                };
                let diff = a - b;
                acc8.multiply_add(diff, diff);
            }

            let aligned_len = dim / 4 * 4;
            let mut acc4 = f64x4::zeros();
            for i in (unrolled_len..aligned_len).step_by(4) {
                // SAFETY: `i + 4 <= dim`, which is in bounds for both slices.
                let (a, b) = unsafe {
                    (
                        f64x4::load_unaligned(x.as_ptr().add(i)),
                        f64x4::load_unaligned(y.as_ptr().add(i)),
                    )
                };
                let diff = a - b;
                acc4.multiply_add(diff, diff);
            }

            let tail: f64 = x[aligned_len..]
                .iter()
                .zip(y[aligned_len..].iter())
                .map(|(&a, &b)| {
                    let diff = a - b;
                    diff * diff
                })
                .sum();

            (acc8.reduce_sum() + acc4.reduce_sum() + tail) as f32
        }
    }

    lance_core::target_kernel! {
        #[target_features("avx")]
        #[candidate(pub(super) L2_F64_AVX: PairKernel<f64>)]
        /// AVX-only path (no FMA): squared diff via `_mm256_mul_pd` + `_mm256_add_pd` for Sandy/Ivy Bridge.
        #[inline]
        pub(super) fn l2_f64_avx(x: &[f64], y: &[f64]) -> f32 {
            // See `l2_f32_avx512` for `min`.
            let dim = x.len().min(y.len());
            let unrolled_len = dim / 4 * 4;

            let mut acc = _mm256_setzero_pd();
            for i in (0..unrolled_len).step_by(4) {
                // SAFETY: `i + 4 <= dim`, which is in bounds for both slices.
                let (a, b) = unsafe {
                    (
                        _mm256_loadu_pd(x.as_ptr().add(i)),
                        _mm256_loadu_pd(y.as_ptr().add(i)),
                    )
                };
                let diff = _mm256_sub_pd(a, b);
                acc = _mm256_add_pd(acc, _mm256_mul_pd(diff, diff));
            }

            // Horizontal sum of __m256d -> f64.
            let lo = _mm256_castpd256_pd128(acc);
            let hi = _mm256_extractf128_pd(acc, 1);
            let sum128 = _mm_add_pd(lo, hi);
            let sum64 = _mm_add_pd(sum128, _mm_unpackhi_pd(sum128, sum128));
            let acc_sum = _mm_cvtsd_f64(sum64);

            let tail: f64 = x[unrolled_len..]
                .iter()
                .zip(y[unrolled_len..].iter())
                .map(|(&a, &b)| {
                    let diff = a - b;
                    diff * diff
                })
                .sum();

            (acc_sum + tail) as f32
        }
    }

    lance_core::target_kernel! {
        #[target_features("avx512f")]
        #[candidate(pub(super) L2_F32_AVX512: PairKernel)]
        /// AVX-512 path for f32: 16-wide `__m512` with `vsubps` + `vfmadd231ps` per iteration.
        #[inline]
        pub(super) fn l2_f32_avx512(x: &[f32], y: &[f32]) -> f32 {
            // Callers pass equal lengths; `min` keeps the unchecked loads in
            // bounds for any input, as a safe function must.
            let dim = x.len().min(y.len());
            let unrolled_len = dim / 16 * 16;

            let mut acc = _mm512_setzero_ps();
            for i in (0..unrolled_len).step_by(16) {
                let (a, b) = unsafe {
                    (
                        _mm512_loadu_ps(x.as_ptr().add(i)),
                        _mm512_loadu_ps(y.as_ptr().add(i)),
                    )
                };
                let diff = _mm512_sub_ps(a, b);
                acc = _mm512_fmadd_ps(diff, diff, acc);
            }

            let tail: f32 = x[unrolled_len..]
                .iter()
                .zip(y[unrolled_len..].iter())
                .map(|(&a, &b)| {
                    let diff = a - b;
                    diff * diff
                })
                .sum();

            _mm512_reduce_add_ps(acc) + tail
        }
    }

    lance_core::target_kernel! {
        #[target_features("avx", "fma")]
        #[candidate(pub(super) L2_F32_AVX_FMA: PairKernel)]
        /// AVX + FMA path for f32. Covers both AvxFma and AVX2 hosts (body uses no AVX2-specific intrinsics).
        #[inline]
        pub(super) fn l2_f32_avx_fma(x: &[f32], y: &[f32]) -> f32 {
            // See `l2_f32_avx512` for `min`.
            let dim = x.len().min(y.len());
            let unrolled_len = dim / 8 * 8;

            let mut acc = _mm256_setzero_ps();
            for i in (0..unrolled_len).step_by(8) {
                let (a, b) = unsafe {
                    (
                        _mm256_loadu_ps(x.as_ptr().add(i)),
                        _mm256_loadu_ps(y.as_ptr().add(i)),
                    )
                };
                let diff = _mm256_sub_ps(a, b);
                acc = _mm256_fmadd_ps(diff, diff, acc);
            }

            let tail: f32 = x[unrolled_len..]
                .iter()
                .zip(y[unrolled_len..].iter())
                .map(|(&a, &b)| {
                    let diff = a - b;
                    diff * diff
                })
                .sum();

            let sum = unsafe { hsum256_ps(acc) };
            sum + tail
        }
    }

    lance_core::target_kernel! {
        #[target_features("avx")]
        #[candidate(pub(super) L2_F32_AVX: PairKernel)]
        /// AVX-only path for f32 (no FMA): squared diff via `_mm256_mul_ps` + `_mm256_add_ps` for Sandy/Ivy Bridge.
        #[inline]
        pub(super) fn l2_f32_avx(x: &[f32], y: &[f32]) -> f32 {
            // See `l2_f32_avx512` for `min`.
            let dim = x.len().min(y.len());
            let unrolled_len = dim / 8 * 8;

            let mut acc = _mm256_setzero_ps();
            for i in (0..unrolled_len).step_by(8) {
                let (a, b) = unsafe {
                    (
                        _mm256_loadu_ps(x.as_ptr().add(i)),
                        _mm256_loadu_ps(y.as_ptr().add(i)),
                    )
                };
                let diff = _mm256_sub_ps(a, b);
                acc = _mm256_add_ps(acc, _mm256_mul_ps(diff, diff));
            }

            let tail: f32 = x[unrolled_len..]
                .iter()
                .zip(y[unrolled_len..].iter())
                .map(|(&a, &b)| {
                    let diff = a - b;
                    diff * diff
                })
                .sum();

            let sum = unsafe { hsum256_ps(acc) };
            sum + tail
        }
    }
}

#[cfg(not(target_arch = "x86_64"))]
lance_core::target_kernel! {
    #[target_features()]
    #[candidate(L2_F64_PORTABLE: PairKernel<f64>)]
    /// `simd::f64` is backed by the baseline NEON or LSX on these architectures.
    #[inline]
    fn l2_f64_portable(x: &[f64], y: &[f64]) -> f32 {
        use crate::simd::f64::{f64x4, f64x8};
        use crate::simd::{FloatSimd, SIMD};

        // Callers pass equal lengths; `min` keeps the unchecked loads in
        // bounds for any input, as a safe function must.
        let dim = x.len().min(y.len());
        let unrolled_len = dim / 8 * 8;

        let mut acc8 = f64x8::zeros();
        for i in (0..unrolled_len).step_by(8) {
            // SAFETY: `i + 8 <= dim`, which is in bounds for both slices.
            let (a, b) = unsafe {
                (
                    f64x8::load_unaligned(x.as_ptr().add(i)),
                    f64x8::load_unaligned(y.as_ptr().add(i)),
                )
            };
            let diff = a - b;
            acc8.multiply_add(diff, diff);
        }

        let aligned_len = dim / 4 * 4;
        let mut acc4 = f64x4::zeros();
        for i in (unrolled_len..aligned_len).step_by(4) {
            // SAFETY: `i + 4 <= dim`, which is in bounds for both slices.
            let (a, b) = unsafe {
                (
                    f64x4::load_unaligned(x.as_ptr().add(i)),
                    f64x4::load_unaligned(y.as_ptr().add(i)),
                )
            };
            let diff = a - b;
            acc4.multiply_add(diff, diff);
        }

        let tail: f64 = x[aligned_len..]
            .iter()
            .zip(y[aligned_len..].iter())
            .map(|(&a, &b)| {
                let diff = a - b;
                diff * diff
            })
            .sum();

        (acc8.reduce_sum() + acc4.reduce_sum() + tail) as f32
    }
}

/// Accumulate squared differences for one dimension into per-target results.
///
/// Separated into its own function so that LLVM sees `row` and `result`
/// as non-aliasing via the function signature (`&[f32]` vs `&mut [f32]`),
/// enabling packed SIMD vectorization (vbroadcastss + vsubps + vfmadd231ps).
#[inline(never)]
fn accumulate_l2_dimension(q: f32, row: &[f32], result: &mut [f32]) {
    for (dist, &target) in result.iter_mut().zip(row.iter()) {
        let diff = q - target;
        *dist += diff * diff;
    }
}

/// Pre-transposed target vectors for batched L2 distance computation.
///
/// Stores targets in SoA layout `[dimension][num_targets]` so the inner
/// distance loop iterates over targets contiguously. The AoS-to-SoA
/// transpose is done once at construction; callers should reuse the
/// struct across many queries to amortize that cost.
///
/// **Cache constraint**: this is designed for cases where
/// `num_targets × dimension × 4` fits in L1 cache (~32 KB), such as PQ
/// sub-vector codebooks (e.g. 256 centroids × 16 dims = 16 KB).
/// For large target sets the SoA layout causes L1 thrashing and
/// [`l2_distance_batch_into`] with its AoS per-target locality is faster.
#[derive(Debug, Clone, DeepSizeOf)]
pub struct L2Prepared {
    transposed: Vec<f32>,
    dimension: usize,
    num_targets: usize,
}

impl L2Prepared {
    /// Transpose `targets` from AoS `[num_targets][dimension]` to SoA layout.
    pub fn new(targets: &[f32], dimension: usize) -> Self {
        let num_targets = targets.len() / dimension;
        debug_assert_eq!(targets.len(), num_targets * dimension);

        let mut transposed = vec![0.0f32; targets.len()];
        for t in 0..num_targets {
            for d in 0..dimension {
                transposed[d * num_targets + t] = targets[t * dimension + d];
            }
        }

        Self {
            transposed,
            dimension,
            num_targets,
        }
    }

    /// Compute L2 distances from `query` to every target, writing into `out`.
    ///
    /// `out` must have length `num_targets`. It will be zeroed before accumulation.
    pub fn distances_into(&self, query: &[f32], out: &mut [f32]) {
        debug_assert_eq!(query.len(), self.dimension);
        debug_assert_eq!(out.len(), self.num_targets);

        out.fill(0.0);
        for (d, &q) in query.iter().enumerate() {
            let row = &self.transposed[d * self.num_targets..][..self.num_targets];
            accumulate_l2_dimension(q, row, out);
        }
    }

    /// Compute L2 distances from `query` to every target.
    pub fn distances(&self, query: &[f32]) -> Vec<f32> {
        let mut result = vec![0.0f32; self.num_targets];
        self.distances_into(query, &mut result);
        result
    }

    /// Return the index of the nearest target to `query`, using `buf` as scratch space.
    ///
    /// `buf` must have length `num_targets`.
    pub fn nearest_into(&self, query: &[f32], buf: &mut [f32]) -> Option<u32> {
        self.distances_into(query, buf);
        crate::kernels::argmin_value_float(buf.iter().copied()).map(|(idx, _)| idx)
    }

    /// Return the index of the nearest target to `query`.
    pub fn nearest(&self, query: &[f32]) -> Option<u32> {
        self.nearest_into(query, &mut vec![0.0f32; self.num_targets])
    }

    /// Number of targets in this set.
    pub fn num_targets(&self) -> usize {
        self.num_targets
    }

    /// Dimension of each target vector.
    pub fn dimension(&self) -> usize {
        self.dimension
    }

    /// Size of the internal buffer in bytes.
    pub fn size_bytes(&self) -> usize {
        self.transposed.len() * std::mem::size_of::<f32>()
    }
}

/// Compute L2 distance between two vectors.
#[inline]
pub fn l2_distance(from: &[f32], to: &[f32]) -> f32 {
    l2(from, to)
}

/// Writes the L2 distance from `from` to each `dimension`-sized vector in `to`
/// into the matching element of `output`.
///
/// # Panics
///
/// Panics if `from.len() != dimension`, if `to.len()` is not a multiple of
/// `dimension`, or if `output.len() != to.len() / dimension`.
///
/// ```
/// # use lance_linalg::distance::l2_distance_batch_into;
/// let mut distances = [0.0; 2];
/// l2_distance_batch_into(&[1.0_f32, 2.0], &[1.0, 2.0, 3.0, 4.0], 2, &mut distances);
/// assert_eq!(distances, [0.0, 8.0]);
/// ```
#[inline]
pub fn l2_distance_batch_into<T: L2>(from: &[T], to: &[T], dimension: usize, output: &mut [f32]) {
    T::l2_batch_into(from, to, dimension, output);
}

fn do_l2_distance_arrow_batch<T: ArrowFloatType>(
    from: &T::ArrayType,
    to: &FixedSizeListArray,
) -> Result<Arc<Float32Array>>
where
    T::Native: L2,
{
    let dimension = to.value_length() as usize;
    debug_assert_eq!(from.len(), dimension);

    // TODO: if we detect there is a run of nulls, should we skip those?
    let to_values =
        to.values()
            .as_any()
            .downcast_ref::<T::ArrayType>()
            .ok_or(Error::ComputeError(format!(
                "Cannot downcast to the same type: {} != {}",
                T::FLOAT_TYPE,
                to.value_type()
            )))?;
    let mut distances = vec![0.0; to.len()];
    l2_distance_batch_into(
        from.as_slice(),
        to_values.as_slice(),
        dimension,
        &mut distances,
    );

    Ok(Arc::new(Float32Array::new(
        distances.into(),
        to.nulls().cloned(),
    )))
}

/// Compute L2 distance between a vector and a batch of vectors.
///
/// Null buffer of `to` is propagated to the returned array.
///
/// Parameters
///
/// - `from`: the vector to compute distance from.
/// - `to`: a list of vectors to compute distance to.
///
/// # Errors
///
/// Returns an error if `from` is an `Int8` array containing nulls, since a null
/// query element has no distance to compute. The unsupported-type and downcast
/// paths return errors of their own; this list is not exhaustive.
///
/// # Panics
///
/// Panics if the length of `from` is not equal to the dimension (value length) of `to`.
pub fn l2_distance_arrow_batch(
    from: &dyn Array,
    to: &FixedSizeListArray,
) -> Result<Arc<Float32Array>> {
    match *from.data_type() {
        DataType::Float16 => do_l2_distance_arrow_batch::<Float16Type>(from.as_primitive(), to),
        DataType::Float32 => do_l2_distance_arrow_batch::<Float32Type>(from.as_primitive(), to),
        DataType::Float64 => do_l2_distance_arrow_batch::<Float64Type>(from.as_primitive(), to),
        DataType::Int8 => do_l2_distance_arrow_batch::<Float32Type>(
            &int8_query_to_f32(from.as_primitive::<Int8Type>())?,
            &to.convert_to_floating_point()?,
        ),
        _ => Err(Error::InvalidArgumentError(format!(
            "Unsupported data type: {}",
            from.data_type()
        ))),
    }
}

#[cfg(test)]
mod tests {
    use super::*;

    use approx::assert_relative_eq;
    use lance_core::utils::cpu::Dispatch;
    use num_traits::ToPrimitive;
    use proptest::prelude::*;

    #[test]
    fn test_l2_rejects_mismatched_lengths() {
        let short = [1.0_f32];
        let long = [1.0_f32, 2.0];

        assert!(std::panic::catch_unwind(|| l2(&short, &long)).is_err());
        assert!(std::panic::catch_unwind(|| l2_f32(&short, &long)).is_err());
        assert!(std::panic::catch_unwind(|| f32::l2(&short, &long)).is_err());
        assert!(std::panic::catch_unwind(|| l2_distance(&short, &long)).is_err());
        assert!(std::panic::catch_unwind(|| l2_distance_batch_vec(&short, &long, 2)).is_err());
        assert!(
            std::panic::catch_unwind(|| l2_distance_batch_vec(&long, &[1.0_f32; 3], 2)).is_err()
        );
        assert!(
            std::panic::catch_unwind(|| l2_distance_batch_into::<f32>(&[], &[], 0, &mut []))
                .is_err()
        );
        assert!(std::panic::catch_unwind(|| l2_distance_uint_scalar(&[1, 2], &[1])).is_err());
        assert!(std::panic::catch_unwind(|| l2_scalar::<u8, f32, 16>(&[1, 2], &[1])).is_err());
    }

    use crate::test_utils::{
        arbitrary_bf16, arbitrary_f16, arbitrary_f32, arbitrary_f64, arbitrary_vector_pair,
        dimension_shard, run_vector_pair_proptest,
    };

    fn l2_distance_batch_vec<T: L2>(from: &[T], to: &[T], dimension: usize) -> Vec<f32> {
        let mut distances = vec![0.0; to.len() / dimension];
        l2_distance_batch_into(from, to, dimension, &mut distances);
        distances
    }

    #[test]
    fn test_l2_f32_dispatch_matches_scalar() {
        // Covers tail handling for lengths around the 16-lane AVX-512 stride.
        for dim in [1usize, 7, 15, 16, 17, 31, 33, 64, 100, 1024] {
            let x: Vec<f32> = (0..dim).map(|i| (i as f32) * 0.5 - 3.0).collect();
            let y: Vec<f32> = (0..dim).map(|i| (i as f32) * -0.25 + 1.5).collect();
            assert_relative_eq!(l2_f32(&x, &y), l2(&x, &y), max_relative = 1e-5);
        }
    }

    /// PQ distance tables call this per sub-vector, so Haswell-baseline
    /// builds must reach the kernel without a runtime dispatch.
    #[cfg(target_arch = "x86_64")]
    #[test]
    fn test_l2_f32_batch_is_static_on_haswell() {
        use lance_core::utils::cpu::CpuFeatures;
        let haswell =
            CpuFeatures::from_target_features(&["avx2", "fma", "f16c", "bmi1", "bmi2", "popcnt"]);
        assert!(haswell.contains(L2_F32_BATCH.candidates()[0].features()));
    }

    #[test]
    fn test_euclidean_distance() {
        let mat = FixedSizeListArray::from_iter_primitive::<Float32Type, _, _>(
            vec![
                Some((0..8).map(|v| Some(v as f32)).collect::<Vec<_>>()),
                Some((1..9).map(|v| Some(v as f32)).collect::<Vec<_>>()),
                Some((2..10).map(|v| Some(v as f32)).collect::<Vec<_>>()),
                Some((3..11).map(|v| Some(v as f32)).collect::<Vec<_>>()),
            ],
            8,
        );
        let point = Float32Array::from((2..10).map(|v| Some(v as f32)).collect::<Vec<_>>());
        let distances = l2_distance_batch_vec(
            point.values(),
            mat.values().as_primitive::<Float32Type>().values(),
            8,
        );

        assert_eq!(distances, vec![32.0, 8.0, 0.0, 8.0]);
    }

    #[test]
    fn test_not_aligned() {
        let mat = (0..6)
            .chain(0..8)
            .chain(1..9)
            .chain(2..10)
            .chain(3..11)
            .map(|v| v as f32)
            .collect::<Vec<_>>();
        let point = Float32Array::from((0..10).map(|v| Some(v as f32)).collect::<Vec<_>>());
        let distances = l2_distance_batch_vec(&point.values()[2..], &mat[6..], 8);

        assert_eq!(distances, vec![32.0, 8.0, 0.0, 8.0]);
    }

    #[test]
    fn test_odd_length_vector() {
        let mat = Float32Array::from_iter((0..5).map(|v| Some(v as f32)));
        let point = Float32Array::from((2..7).map(|v| Some(v as f32)).collect::<Vec<_>>());
        let distances = l2_distance_batch_vec(point.values(), mat.values(), 5);

        assert_eq!(distances, vec![20.0]);
    }

    #[test]
    fn test_l2_distance_cases() {
        let values: Float32Array = vec![
            0.25335717, 0.24663818, 0.26330215, 0.14988247, 0.06042378, 0.21077952, 0.26687378,
            0.22145681, 0.18319066, 0.18688454, 0.05216244, 0.11470364, 0.10554603, 0.19964123,
            0.06387895, 0.18992095, 0.00123718, 0.13500804, 0.09516747, 0.19508345, 0.2582458,
            0.1211653, 0.21121833, 0.24809816, 0.04078768, 0.19586588, 0.16496408, 0.14766085,
            0.04898421, 0.14728612, 0.21263947, 0.16763233,
        ]
        .into();

        let q: Float32Array = vec![
            0.18549609,
            0.29954708,
            0.28318876,
            0.05424477,
            0.093134984,
            0.21580857,
            0.2951282,
            0.19866848,
            0.13868214,
            0.19819534,
            0.23271298,
            0.047727287,
            0.14394054,
            0.023316395,
            0.18589257,
            0.037315924,
            0.07037327,
            0.32609823,
            0.07344752,
            0.020155912,
            0.18485495,
            0.32763934,
            0.14296658,
            0.04498596,
            0.06254237,
            0.24348071,
            0.16009757,
            0.053892266,
            0.05918874,
            0.040363103,
            0.19913352,
            0.14545348,
        ]
        .into();

        let d = l2_distance_batch_vec(q.values(), values.values(), 32);
        assert_relative_eq!(0.319_357_84, d[0]);
    }

    /// Reference implementation of L2 distance.
    ///
    /// Note that we skip the final square root step for performance reasons.
    fn l2_distance_reference(x: &[f64], y: &[f64]) -> f64 {
        x.iter()
            .zip(y.iter())
            .map(|(x, y)| (*x - *y).powi(2))
            .sum::<f64>()
    }

    fn do_l2_test<T: L2 + ToPrimitive>(x: &[T], y: &[T]) -> std::result::Result<(), TestCaseError> {
        let x_f64 = x.iter().map(|v| v.to_f64().unwrap()).collect::<Vec<f64>>();
        let y_f64 = y.iter().map(|v| v.to_f64().unwrap()).collect::<Vec<f64>>();

        let result = l2(x, y);
        let reference = l2_distance_reference(&x_f64, &y_f64) as f32;

        prop_assert!(approx::relative_eq!(result, reference, max_relative = 1e-6));
        Ok(())
    }

    #[test]
    fn test_l2_distance_f16_max() {
        let x = vec![f16::MAX; 4048];
        let y = vec![-f16::MAX; 4048];
        do_l2_test(&x, &y).unwrap();
    }

    #[rstest::rstest]
    fn test_l2_distance_f32(
        #[values(0, 1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11, 12, 13, 14, 15)] shard: usize,
    ) {
        run_vector_pair_proptest(arbitrary_f32, dimension_shard(shard), |x, y| {
            do_l2_test(&x, &y)
        });
    }

    #[rstest::rstest]
    fn test_l2_distance_f64(
        #[values(0, 1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11, 12, 13, 14, 15)] shard: usize,
    ) {
        run_vector_pair_proptest(arbitrary_f64, dimension_shard(shard), |x, y| {
            do_l2_test(&x, &y)
        });
    }

    /// Every host-supported f32 kernel, single-pair and batch, must agree with
    /// an f64 reference. Prefixes of length 8 and 16 pin the batch kernels'
    /// PQ-width fast paths regardless of the generated dimension.
    #[rstest::rstest]
    fn test_l2_f32_kernels_match_reference(
        #[values(0, 1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11, 12, 13, 14, 15)] shard: usize,
    ) {
        run_vector_pair_proptest(arbitrary_f32, dimension_shard(shard), |x, y| {
            for dimension in [8, 16, x.len()].into_iter().filter(|&d| d <= x.len()) {
                let (x, y) = (&x[..dimension], &y[..dimension]);
                let x_f64 = x.iter().map(|&v| v as f64).collect::<Vec<_>>();
                let y_f64 = y.iter().map(|&v| v as f64).collect::<Vec<_>>();
                let want = l2_distance_reference(&x_f64, &y_f64) as f32;

                for candidate in L2_F32.candidates() {
                    let Some(kernel) = candidate.kernel() else {
                        continue;
                    };
                    let got = kernel.call(x, y);
                    prop_assert!(
                        approx::relative_eq!(got, want, max_relative = 1e-3),
                        "{} at dim {dimension}: {got} != {want}",
                        candidate.name()
                    );
                }

                // Up to 16 dimensions the batch kernel must match the pair
                // kernel bit for bit; above that it uses the scalar kernel.
                #[cfg(target_arch = "x86_64")]
                if dimension <= 16
                    && let (Some(pair), Some(batch)) = (
                        x86::L2_F32_AVX_FMA.kernel(),
                        x86::L2_F32_BATCH_AVX_FMA.kernel(),
                    )
                {
                    let mut got = [f32::NAN];
                    batch.call(x, y, dimension, &mut got);
                    prop_assert_eq!(
                        got[0].to_bits(),
                        pair.call(x, y).to_bits(),
                        "dim {}",
                        dimension
                    );
                }

                // The second vector equals the key, so its distance is exactly 0.
                let batch = [y, x].concat();
                for candidate in L2_F32_BATCH.candidates() {
                    let Some(kernel) = candidate.kernel() else {
                        continue;
                    };
                    let mut got = [f32::NAN; 2];
                    kernel.call(x, &batch, dimension, &mut got);
                    prop_assert!(
                        approx::relative_eq!(got[0], want, max_relative = 1e-3) && got[1] == 0.0,
                        "{} at dim {dimension}: {got:?} != [{want}, 0]",
                        candidate.name()
                    );
                }
            }
            Ok(())
        });
    }

    /// Every host-supported f64 kernel must agree with an f64 reference.
    #[rstest::rstest]
    fn test_l2_f64_kernels_match_reference(
        #[values(0, 1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11, 12, 13, 14, 15)] shard: usize,
    ) {
        run_vector_pair_proptest(arbitrary_f64, dimension_shard(shard), |x, y| {
            let want = l2_distance_reference(&x, &y) as f32;
            for candidate in L2_F64.candidates() {
                let Some(kernel) = candidate.kernel() else {
                    continue;
                };
                let got = kernel.call(&x, &y);
                prop_assert!(
                    approx::relative_eq!(got, want, max_relative = 1e-6),
                    "{} at dim {}: {got} != {want}",
                    candidate.name(),
                    x.len()
                );
            }
            Ok(())
        });
    }

    /// Every host-supported half-precision kernel must agree with an f64
    /// reference.
    fn check_half_l2_kernels<T: ToPrimitive>(
        dispatch: &Dispatch<PairKernel<T>>,
        x: &[T],
        y: &[T],
    ) -> std::result::Result<(), TestCaseError> {
        let x_f64 = x.iter().map(|v| v.to_f64().unwrap()).collect::<Vec<_>>();
        let y_f64 = y.iter().map(|v| v.to_f64().unwrap()).collect::<Vec<_>>();
        let want = l2_distance_reference(&x_f64, &y_f64) as f32;
        for candidate in dispatch.candidates() {
            let Some(kernel) = candidate.kernel() else {
                continue;
            };
            let got = kernel.call(x, y);
            prop_assert!(
                approx::relative_eq!(got, want, max_relative = 1e-6),
                "{} at dim {}: {got} != {want}",
                candidate.name(),
                x.len()
            );
        }
        Ok(())
    }

    #[rstest::rstest]
    fn test_l2_f16_kernels_match_reference(
        #[values(0, 1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11, 12, 13, 14, 15)] shard: usize,
    ) {
        run_vector_pair_proptest(arbitrary_f16, dimension_shard(shard), |x, y| {
            check_half_l2_kernels(&L2_F16, &x, &y)
        });
    }

    #[rstest::rstest]
    fn test_l2_bf16_kernels_match_reference(
        #[values(0, 1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11, 12, 13, 14, 15)] shard: usize,
    ) {
        run_vector_pair_proptest(arbitrary_bf16, dimension_shard(shard), |x, y| {
            check_half_l2_kernels(&L2_BF16, &x, &y)
        });
    }

    // Test L2 distance over different types.
    // * L2 is valid over the entire range of f16.
    // * L2 is valid over f32 and bf16 in the range of +-1e12.
    // * L2 for f64 should match the reference implementation.
    proptest::proptest! {
        #[test]
        fn test_l2_distance_f16((x, y) in arbitrary_vector_pair(arbitrary_f16, 4..4048)) {
            do_l2_test(&x, &y)?;
        }

        #[test]
        fn test_l2_distance_bf16((x, y) in arbitrary_vector_pair(arbitrary_bf16, 4..4048)){
            do_l2_test(&x, &y)?;
        }
    }

    #[test]
    fn test_uint8_l2_edge_cases() {
        let q = vec![0_u8; 2048];
        let v = vec![0_u8; 2048];
        assert_eq!(l2_distance_uint_scalar(&q, &v), 0.0);

        let q = vec![0_u8; 2048];
        let v = vec![255_u8; 2048];
        assert_eq!(
            l2_distance_uint_scalar(&q, &v),
            (255_u32.pow(2) * 2048) as f32
        );
        assert_eq!(
            l2_distance_uint_scalar(&v, &q),
            (255_u32.pow(2) * 2048) as f32
        );
    }

    #[test]
    fn test_l2_targets_matches_scalar() {
        let cases = vec![
            (16, 8),   // small target count
            (16, 16),  // exact SIMD width
            (16, 256), // PQ-like: 256 centroids, 16-dim sub-vectors
            (16, 17),  // one remainder
            (16, 31),  // 15 remainder
            (1, 32),   // dim=1
            (3, 20),   // odd dimension
            (128, 64), // larger dimension
        ];

        for (dim, num_targets) in cases {
            let query: Vec<f32> = (0..dim).map(|i| (i as f32) * 0.1 + 0.05).collect();
            let targets: Vec<f32> = (0..dim * num_targets)
                .map(|i| ((i * 7 + 3) % 100) as f32 * 0.01)
                .collect();

            let expected: Vec<f32> = targets
                .chunks_exact(dim)
                .map(|v| l2_scalar::<f32, f32, 16>(&query, v))
                .collect();

            let prepared = L2Prepared::new(&targets, dim);
            let actual = prepared.distances(&query);

            assert_eq!(
                actual.len(),
                expected.len(),
                "length mismatch for dim={dim}, num_targets={num_targets}"
            );
            for (i, (a, e)) in actual.iter().zip(expected.iter()).enumerate() {
                assert!(
                    approx::relative_eq!(a, e, max_relative = 1e-6),
                    "mismatch at index {i} for dim={dim}, num_targets={num_targets}: \
                     prepared={a}, scalar={e}"
                );
            }
        }
    }

    #[test]
    fn test_l2_targets_zeros() {
        let dim = 16;
        let num_targets = 32;
        let query = vec![0.0f32; dim];
        let targets = vec![0.0f32; dim * num_targets];

        let prepared = L2Prepared::new(&targets, dim);
        let distances = prepared.distances(&query);
        assert_eq!(distances.len(), num_targets);
        for d in &distances {
            assert_eq!(*d, 0.0);
        }
    }

    #[test]
    fn test_l2_targets_known_values() {
        let dim = 2;
        let query = vec![1.0f32, 0.0];

        // 16 targets: [1,0], [0,1], [2,0], [0,0], then 12x [0,0]
        let mut targets = vec![1.0, 0.0, 0.0, 1.0, 2.0, 0.0, 0.0, 0.0];
        for _ in 4..16 {
            targets.extend_from_slice(&[0.0, 0.0]);
        }

        let prepared = L2Prepared::new(&targets, dim);
        let distances = prepared.distances(&query);
        assert_eq!(distances.len(), 16);
        assert_relative_eq!(distances[0], 0.0);
        assert_relative_eq!(distances[1], 2.0);
        assert_relative_eq!(distances[2], 1.0);
        assert_relative_eq!(distances[3], 1.0);
        for d in &distances[4..] {
            assert_relative_eq!(*d, 1.0);
        }
    }

    #[test]
    fn test_l2_targets_reuse() {
        // Verify that the same L2Prepared can be queried multiple times
        let dim = 4;
        let targets = vec![1.0, 2.0, 3.0, 4.0, 5.0, 6.0, 7.0, 8.0];
        let prepared = L2Prepared::new(&targets, dim);

        let q1 = vec![1.0, 2.0, 3.0, 4.0];
        let q2 = vec![5.0, 6.0, 7.0, 8.0];

        let d1 = prepared.distances(&q1);
        let d2 = prepared.distances(&q2);

        assert_relative_eq!(d1[0], 0.0); // q1 == target[0]
        assert_relative_eq!(d2[1], 0.0); // q2 == target[1]
    }

    /// `l2_batch_into` must agree with the per-vector `l2`, both for the f32
    /// batch kernel and for the per-vector default that f64 uses.
    #[rstest::rstest]
    #[case::dim_8(8)]
    #[case::dim_12(12)]
    #[case::dim_16(16)]
    #[case::dim_32(32)]
    #[case::dim_1024(1024)]
    fn test_l2_batch_into_matches_per_vector_l2(#[case] dimension: usize) {
        fn check<T: L2 + num_traits::FromPrimitive + Copy>(dimension: usize) {
            let num_vectors = 130;
            let x: Vec<T> = (0..dimension)
                .map(|i| T::from_f32(((i % 13) as f32) * 0.25 + 1.0).unwrap())
                .collect();
            let batch: Vec<T> = (0..dimension * num_vectors)
                .map(|i| T::from_f32(((i % 11) as f32) * 0.5 - 2.0).unwrap())
                .collect();

            let mut got = vec![f32::NAN; num_vectors];
            T::l2_batch_into(&x, &batch, dimension, &mut got);

            for (g, y) in got.iter().zip(batch.chunks_exact(dimension)) {
                let w = T::l2(&x, y);
                assert!(
                    approx::relative_eq!(*g, w, epsilon = 1e-4, max_relative = 1e-5),
                    "dim {dimension}: batch {g} != per-vector {w}"
                );
            }
        }
        check::<f32>(dimension);
        check::<f64>(dimension);
    }

    #[rstest::rstest]
    #[case::short(1)]
    #[case::long(3)]
    fn test_l2_batch_into_rejects_wrong_output_len(#[case] output_len: usize) {
        let batch = [1.0_f32; 4];
        let mut output = vec![0.0; output_len];
        let result = std::panic::catch_unwind(move || {
            l2_distance_batch_into(&[1.0_f32, 2.0], &batch, 2, &mut output)
        });
        assert!(result.is_err());
    }
}
