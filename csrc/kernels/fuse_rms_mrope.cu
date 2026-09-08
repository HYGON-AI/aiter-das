// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include "hip/hip_runtime.h"
#include <torch/extension.h>
#include <ATen/ATen.h>
#include <ATen/AccumulateType.h>
#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <c10/cuda/CUDAMathCompat.h>
#include <c10/macros/Macros.h>

#include "rocm_ops.hpp"

namespace aiter {

void fuse_rms_mrope(
    torch::Tensor& q,
    torch::Tensor& k,
    const torch::Tensor& cos,
    const torch::Tensor& sin,
    const std::vector<int64_t>& mrope_section,
    int64_t head_size,
    bool is_interleaved,
    const torch::Tensor& weight_q,
    const torch::Tensor& weight_k,
    const torch::optional<torch::Tensor>& residual_q = torch::nullopt,
    const torch::optional<torch::Tensor>& residual_k = torch::nullopt,
    double epsilon = 1e-6);

template <typename T, int N>
struct alignas(sizeof(T) * N) aligned_vector {
    T val[N];
    __host__ __device__ inline T& operator[](int i) { return val[i]; }
};

namespace {

template <typename T, int reducesize = 64>
__inline__ __device__ T WarpReduceSum(T val) {
#pragma unroll
    for (int offset = reducesize / 2; offset > 0; offset >>= 1) {
        val += __shfl_down(val, offset);
    }
    return val;
}

// Branchless neo-RoPE on a vec. half_rd must be power-of-2 (32/64).
// Flat smem: pair of index p is at (p ^ half_rd).
// out = x * cos + sign * pair * sin, sign = -1 (1st half) / +1 (2nd half).
template <typename scalar_t, int Vec>
__device__ inline void apply_rope_vec(
    const scalar_t* x_vec,
    scalar_t* out_vec,
    const scalar_t* x_smem,
    const scalar_t* smem_cos,
    const scalar_t* smem_sin,
    int idx,
    int half_rd) {
#pragma unroll
    for (int i = 0; i < Vec; i++) {
        const int p = idx + i;
        const int pair = p ^ half_rd;
        const int ci = p & (half_rd - 1);
        const float sign = (p & half_rd) ? 1.f : -1.f;
        const float x = static_cast<float>(x_vec[i]);
        const float c = static_cast<float>(smem_cos[ci]);
        const float s = static_cast<float>(smem_sin[ci]);
        const float y = static_cast<float>(x_smem[pair]);
        out_vec[i] = static_cast<scalar_t>(x * c + sign * y * s);
    }
}

// Per-warp RMSNorm: reduction + rstd broadcast via shuffle (no block barrier).
// Safe to call from divergent Q/K pipeline partitions.
template <typename T_ACC, typename scalar_t, int Vec = 4, int block_size = 512, int num_warp, bool pipeline = false, bool is_q = false>
inline __device__ void apply_rmsnorm(scalar_t* input, scalar_t* gamma, int cols, T_ACC eps, scalar_t* input_vec) {
    T_ACC val = 0;
    int tid;
    if (pipeline && is_q) {
        tid = threadIdx.x - C10_WARP_SIZE;
    } else {
        tid = threadIdx.x;
    }
    int tcol = cols * num_warp / Vec;

    using LoadT = aiter::aligned_vector<scalar_t, Vec>;
    int64_t idx = tid;
    idx *= Vec;
    if (tid < tcol) {
        *(LoadT*)input_vec = *(LoadT*)(input + idx);
#pragma unroll
        for (int ii = 0; ii < Vec; ii++) {
            val += static_cast<T_ACC>(input_vec[ii]) * static_cast<T_ACC>(input_vec[ii]);
        }
    }

    val = WarpReduceSum<T_ACC>(val);
    val = __shfl(val, 0);
    T_ACC trstd = c10::cuda::compat::rsqrt(val / cols + eps);
    if (tid < tcol) {
#pragma unroll
        for (int ii = 0; ii < Vec; ii++) {
            int jj = (tid * Vec + ii) % cols;
            input_vec[ii] = static_cast<T_ACC>(input_vec[ii]) * trstd * static_cast<T_ACC>(gamma[jj]);
        }
    }
}

template <typename T_ACC, typename scalar_t, int Vec = 4, int block_size = 512, int num_warp, bool pipeline = false, bool is_q = false>
inline __device__ void apply_rmsnorm_residual(scalar_t* input, scalar_t* gamma, scalar_t* residual, int cols, T_ACC eps, scalar_t* input_vec) {
    T_ACC val = 0;
    int tid;
    if (pipeline && is_q) {
        tid = threadIdx.x - C10_WARP_SIZE;
    } else {
        tid = threadIdx.x;
    }
    int tcol = cols * num_warp / Vec;
    using LoadT = aiter::aligned_vector<scalar_t, Vec>;
    scalar_t residual_vec[Vec];
    int64_t idx = tid;
    idx *= Vec;
    if (tid < tcol) {
        *(LoadT*)input_vec = *(LoadT*)(input + idx);
        *(LoadT*)residual_vec = *(LoadT*)(residual + idx);
#pragma unroll
        for (int ii = 0; ii < Vec; ii++) {
            residual_vec[ii] += input_vec[ii];
            val += static_cast<T_ACC>(residual_vec[ii]) * static_cast<T_ACC>(residual_vec[ii]);
        }
    }

    val = WarpReduceSum<T_ACC>(val);
    val = __shfl(val, 0);
    T_ACC trstd = c10::cuda::compat::rsqrt(val / cols + eps);

    if (tid < tcol) {
#pragma unroll
        for (int ii = 0; ii < Vec; ii++) {
            int jj = (tid * Vec + ii) % cols;
            input_vec[ii] = static_cast<T_ACC>(residual_vec[ii]) * trstd * static_cast<T_ACC>(gamma[jj]);
        }
    }
}

template <typename T_ACC, typename scalar_t, bool is_interleaved, bool RESIDUAL, int vec_size, int num_warp, int head_size, int block_size>
__global__ void fuse_rms_mrope_kernel_optimized(
    scalar_t* __restrict__ q_ptr,
    scalar_t* __restrict__ k_ptr,
    const scalar_t* __restrict__ cos,
    const scalar_t* __restrict__ sin,
    int num_tokens,
    int n_qh,
    int n_kh,
    int rd,
    int mrope_section_t,
    int mrope_section_h,
    int mrope_section_w,
    scalar_t* gamma_q,
    scalar_t* gamma_k,
    scalar_t* residual_q,
    scalar_t* residual_k,
    scalar_t eps) {
    int pid = blockIdx.x;
    if (pid >= num_tokens) return;

    __shared__ scalar_t smem_cos[head_size / 2];
    __shared__ scalar_t smem_sin[head_size / 2];

    int half_rd = rd / 2;
    int tid = threadIdx.x;

    if (tid < half_rd) {
        int64_t token_stride = num_tokens * half_rd;
        const scalar_t* t_cos_ptr = cos + pid * half_rd;
        const scalar_t* h_cos_ptr = t_cos_ptr + token_stride;
        const scalar_t* w_cos_ptr = h_cos_ptr + token_stride;
        const scalar_t* t_sin_ptr = sin + pid * half_rd;
        const scalar_t* h_sin_ptr = t_sin_ptr + token_stride;
        const scalar_t* w_sin_ptr = h_sin_ptr + token_stride;
        scalar_t c, s;

        bool is_h, is_w;
        if constexpr (is_interleaved) {
            is_h = ((tid % 3) == 1) && (tid <= 3 * mrope_section_h);
            is_w = ((tid % 3) == 2) && (tid <= 3 * mrope_section_w);
        } else {
            is_h = (tid >= mrope_section_t) && (tid < mrope_section_t + mrope_section_h);
            is_w = (tid >= mrope_section_t + mrope_section_h) && (tid < half_rd);
        }

        if (is_h) {
            c = h_cos_ptr[tid];
            s = h_sin_ptr[tid];
        } else if (is_w) {
            c = w_cos_ptr[tid];
            s = w_sin_ptr[tid];
        } else {
            c = t_cos_ptr[tid];
            s = t_sin_ptr[tid];
        }

        smem_cos[tid] = c;
        smem_sin[tid] = s;
    }

    __syncthreads();

    using LoadT = aiter::aligned_vector<scalar_t, vec_size>;
    int q_stride = pid * n_qh * head_size;
    int k_stride = pid * n_kh * head_size;
    auto q_curr = q_ptr + q_stride;
    auto k_curr = k_ptr + k_stride;
    int idx = tid * vec_size;
    int head_idx_k = 0, head_idx_q = 0;

    for (; head_idx_k < n_kh; head_idx_k += num_warp, head_idx_q += num_warp) {
        scalar_t* ptr_k = k_curr + head_idx_k * head_size;
        scalar_t* ptr_q = q_curr + head_idx_q * head_size;

        scalar_t input_vec_k[vec_size];
        scalar_t input_vec_q[vec_size];
        if constexpr (RESIDUAL) {
            scalar_t* residual_q_ptr = residual_q + q_stride + head_idx_q * head_size;
            scalar_t* residual_k_ptr = residual_k + k_stride + head_idx_k * head_size;
            apply_rmsnorm_residual<T_ACC, scalar_t, vec_size, block_size, num_warp, false, false>(ptr_q, gamma_q, residual_q_ptr, head_size, eps, input_vec_q);
            apply_rmsnorm_residual<T_ACC, scalar_t, vec_size, block_size, num_warp, false, false>(ptr_k, gamma_k, residual_k_ptr, head_size, eps, input_vec_k);
        } else {
            apply_rmsnorm<T_ACC, scalar_t, vec_size, block_size, num_warp, false, false>(ptr_q, gamma_q, head_size, eps, input_vec_q);
            apply_rmsnorm<T_ACC, scalar_t, vec_size, block_size, num_warp, false, false>(ptr_k, gamma_k, head_size, eps, input_vec_k);
        }

        __shared__ scalar_t k_smem[head_size * num_warp];
        __shared__ scalar_t q_smem[head_size * num_warp];
#pragma unroll
        for (int i = 0; i < vec_size; i++) {
            k_smem[idx + i] = input_vec_k[i];
            q_smem[idx + i] = input_vec_q[i];
        }
        __syncthreads();
        apply_rope_vec<scalar_t, vec_size>(input_vec_k, input_vec_k, k_smem, smem_cos, smem_sin, idx, half_rd);
        apply_rope_vec<scalar_t, vec_size>(input_vec_q, input_vec_q, q_smem, smem_cos, smem_sin, idx, half_rd);
        *(LoadT*)(ptr_k + idx) = *(LoadT*)input_vec_k;
        *(LoadT*)(ptr_q + idx) = *(LoadT*)input_vec_q;
    }

    for (head_idx_q = n_kh; head_idx_q < n_qh; head_idx_q += num_warp) {
        scalar_t* ptr_q = q_curr + head_idx_q * head_size;
        scalar_t input_vec_q[vec_size];
        if constexpr (RESIDUAL) {
            scalar_t* residual_q_ptr = residual_q + q_stride + head_idx_q * head_size;
            apply_rmsnorm_residual<T_ACC, scalar_t, vec_size, block_size, num_warp, false, false>(ptr_q, gamma_q, residual_q_ptr, head_size, eps, input_vec_q);
        } else {
            apply_rmsnorm<T_ACC, scalar_t, vec_size, block_size, num_warp, false, false>(ptr_q, gamma_q, head_size, eps, input_vec_q);
        }
        __shared__ scalar_t q_smem[head_size * num_warp];
#pragma unroll
        for (int i = 0; i < vec_size; i++) {
            q_smem[idx + i] = input_vec_q[i];
        }
        __syncthreads();
        apply_rope_vec<scalar_t, vec_size>(input_vec_q, input_vec_q, q_smem, smem_cos, smem_sin, idx, half_rd);
        *(LoadT*)(ptr_q + idx) = *(LoadT*)input_vec_q;
    }
}

// Q/K overlapped path for n_kh==1: warp0 handles K, remaining warps handle Q.
// All threads share one loop and identical __syncthreads counts (no divergent barriers).
template <typename T_ACC, typename scalar_t, bool is_interleaved, bool RESIDUAL, int vec_size, int num_warp, int head_size, int block_size>
__global__ void fuse_rms_mrope_kernel_optimized_pipeline(
    scalar_t* __restrict__ q_ptr,
    scalar_t* __restrict__ k_ptr,
    const scalar_t* __restrict__ cos,
    const scalar_t* __restrict__ sin,
    int num_tokens,
    int n_qh,
    int n_kh,
    int rd,
    int mrope_section_t,
    int mrope_section_h,
    int mrope_section_w,
    scalar_t* gamma_q,
    scalar_t* gamma_k,
    scalar_t* residual_q,
    scalar_t* residual_k,
    scalar_t eps) {
    int pid = blockIdx.x;
    if (pid >= num_tokens) return;
    const int warp_size = C10_WARP_SIZE;

    constexpr int num_warp_q = num_warp - 1;
    __shared__ scalar_t smem_cos[head_size / 2];
    __shared__ scalar_t smem_sin[head_size / 2];
    __shared__ scalar_t q_smem[head_size * num_warp_q];
    __shared__ scalar_t k_smem[head_size];

    int half_rd = rd / 2;
    int tid = threadIdx.x;
    const bool is_q_worker = (tid >= warp_size);
    const bool is_k_worker = (tid < warp_size);

    if (tid < half_rd) {
        int64_t token_stride = num_tokens * half_rd;
        const scalar_t* t_cos_ptr = cos + pid * half_rd;
        const scalar_t* h_cos_ptr = t_cos_ptr + token_stride;
        const scalar_t* w_cos_ptr = h_cos_ptr + token_stride;
        const scalar_t* t_sin_ptr = sin + pid * half_rd;
        const scalar_t* h_sin_ptr = t_sin_ptr + token_stride;
        const scalar_t* w_sin_ptr = h_sin_ptr + token_stride;
        scalar_t c, s;

        bool is_h, is_w;
        if constexpr (is_interleaved) {
            is_h = ((tid % 3) == 1) && (tid <= 3 * mrope_section_h);
            is_w = ((tid % 3) == 2) && (tid <= 3 * mrope_section_w);
        } else {
            is_h = (tid >= mrope_section_t) && (tid < mrope_section_t + mrope_section_h);
            is_w = (tid >= mrope_section_t + mrope_section_h) && (tid < half_rd);
        }

        if (is_h) {
            c = h_cos_ptr[tid];
            s = h_sin_ptr[tid];
        } else if (is_w) {
            c = w_cos_ptr[tid];
            s = w_sin_ptr[tid];
        } else {
            c = t_cos_ptr[tid];
            s = t_sin_ptr[tid];
        }

        smem_cos[tid] = c;
        smem_sin[tid] = s;
    }
    __syncthreads();

    using LoadT = aiter::aligned_vector<scalar_t, vec_size>;

    auto q_curr = q_ptr + pid * n_qh * head_size;
    auto k_curr = k_ptr + pid * n_kh * head_size;

    for (int head_idx_q = 0; head_idx_q < n_qh; head_idx_q += num_warp_q) {
        scalar_t input_vec[vec_size];
        int local_tid = is_q_worker ? (tid - warp_size) : tid;
        int64_t idx = local_tid * vec_size;
        bool do_k = is_k_worker && (head_idx_q == 0);

        if (is_q_worker) {
            scalar_t* ptr_q = q_curr + head_idx_q * head_size;
            if constexpr (RESIDUAL) {
                scalar_t* residual_q_ptr = residual_q + pid * n_qh * head_size + head_idx_q * head_size;
                apply_rmsnorm_residual<T_ACC, scalar_t, vec_size, block_size, num_warp_q, true, true>(
                    ptr_q, gamma_q, residual_q_ptr, head_size, eps, input_vec);
            } else {
                apply_rmsnorm<T_ACC, scalar_t, vec_size, block_size, num_warp_q, true, true>(
                    ptr_q, gamma_q, head_size, eps, input_vec);
            }
#pragma unroll
            for (int i = 0; i < vec_size; i++) {
                q_smem[idx + i] = input_vec[i];
            }
        } else if (do_k) {
            scalar_t* ptr_k = k_curr;
            if constexpr (RESIDUAL) {
                scalar_t* residual_k_ptr = residual_k + pid * n_kh * head_size;
                apply_rmsnorm_residual<T_ACC, scalar_t, vec_size, block_size, 1, false, false>(
                    ptr_k, gamma_k, residual_k_ptr, head_size, eps, input_vec);
            } else {
                apply_rmsnorm<T_ACC, scalar_t, vec_size, block_size, 1, false, false>(
                    ptr_k, gamma_k, head_size, eps, input_vec);
            }
#pragma unroll
            for (int i = 0; i < vec_size; i++) {
                k_smem[idx + i] = input_vec[i];
            }
        }

        __syncthreads();

        if (is_q_worker) {
            scalar_t* ptr_q = q_curr + head_idx_q * head_size;
            scalar_t output[vec_size];
            apply_rope_vec<scalar_t, vec_size>(input_vec, output, q_smem, smem_cos, smem_sin, idx, half_rd);
            *(LoadT*)(ptr_q + idx) = *(LoadT*)output;
        } else if (do_k) {
            scalar_t* ptr_k = k_curr;
            scalar_t output[vec_size];
            apply_rope_vec<scalar_t, vec_size>(input_vec, output, k_smem, smem_cos, smem_sin, idx, half_rd);
            *(LoadT*)(ptr_k + idx) = *(LoadT*)output;
        }

        __syncthreads();
    }
}

template <typename T_ACC, typename scalar_t, bool is_interleaved, bool RESIDUAL, int vec_size, int num_warp, int head_size, int block_size>
__global__ void fuse_rms_mrope_kernel_optimized_small(
    scalar_t* __restrict__ q_ptr,
    scalar_t* __restrict__ k_ptr,
    const scalar_t* __restrict__ cos,
    const scalar_t* __restrict__ sin,
    int num_tokens,
    int n_qh,
    int n_kh,
    int rd,
    int mrope_section_t,
    int mrope_section_h,
    int mrope_section_w,
    scalar_t* gamma_q,
    scalar_t* gamma_k,
    scalar_t* residual_q,
    scalar_t* residual_k,
    scalar_t eps) {
    int pid = blockIdx.x;
    if (pid >= num_tokens) return;
    __shared__ scalar_t smem_cos[head_size / 2];
    __shared__ scalar_t smem_sin[head_size / 2];

    int half_rd = rd / 2;
    int tid = threadIdx.x;

    if (tid < half_rd) {
        int64_t token_stride = num_tokens * half_rd;
        const scalar_t* t_cos_ptr = cos + pid * half_rd;
        const scalar_t* h_cos_ptr = t_cos_ptr + token_stride;
        const scalar_t* w_cos_ptr = h_cos_ptr + token_stride;
        const scalar_t* t_sin_ptr = sin + pid * half_rd;
        const scalar_t* h_sin_ptr = t_sin_ptr + token_stride;
        const scalar_t* w_sin_ptr = h_sin_ptr + token_stride;
        scalar_t c, s;

        bool is_h, is_w;
        if constexpr (is_interleaved) {
            is_h = ((tid % 3) == 1) && (tid <= 3 * mrope_section_h);
            is_w = ((tid % 3) == 2) && (tid <= 3 * mrope_section_w);
        } else {
            is_h = (tid >= mrope_section_t) && (tid < mrope_section_t + mrope_section_h);
            is_w = (tid >= mrope_section_t + mrope_section_h) && (tid < half_rd);
        }

        if (is_h) {
            c = h_cos_ptr[tid];
            s = h_sin_ptr[tid];
        } else if (is_w) {
            c = w_cos_ptr[tid];
            s = w_sin_ptr[tid];
        } else {
            c = t_cos_ptr[tid];
            s = t_sin_ptr[tid];
        }

        smem_cos[tid] = c;
        smem_sin[tid] = s;
    }

    __syncthreads();

    using LoadT = aiter::aligned_vector<scalar_t, vec_size>;

    auto q_curr = q_ptr + pid * n_qh * head_size;
    auto k_curr = k_ptr + pid * n_kh * head_size;

    for (int head_idx_q = 0; head_idx_q < n_qh; head_idx_q += num_warp) {
        scalar_t* ptr_q = q_curr + head_idx_q * head_size;
        int64_t idx = tid * vec_size;
        scalar_t input_vec_q[vec_size];
        if constexpr (RESIDUAL) {
            scalar_t* residual_q_ptr = residual_q + pid * n_qh * head_size + head_idx_q * head_size;
            apply_rmsnorm_residual<T_ACC, scalar_t, vec_size, block_size, num_warp, false, false>(ptr_q, gamma_q, residual_q_ptr, head_size, eps, input_vec_q);
        } else {
            apply_rmsnorm<T_ACC, scalar_t, vec_size, block_size, num_warp, false, false>(ptr_q, gamma_q, head_size, eps, input_vec_q);
        }
        __shared__ scalar_t q_smem[head_size * num_warp];
#pragma unroll
        for (int i = 0; i < vec_size; i++) {
            q_smem[idx + i] = input_vec_q[i];
        }
        __syncthreads();
        scalar_t output_q[vec_size];
        apply_rope_vec<scalar_t, vec_size>(input_vec_q, output_q, q_smem, smem_cos, smem_sin, idx, half_rd);
        *(LoadT*)(ptr_q + idx) = *(LoadT*)output_q;
    }

    for (int head_idx_k = 0; head_idx_k < n_kh; head_idx_k += num_warp) {
        scalar_t* ptr_k = k_curr + head_idx_k * head_size;
        int64_t idx = tid * vec_size;
        scalar_t input_vec_k[vec_size];
        if constexpr (RESIDUAL) {
            scalar_t* residual_k_ptr = residual_k + pid * n_kh * head_size + head_idx_k * head_size;
            apply_rmsnorm_residual<T_ACC, scalar_t, vec_size, block_size, num_warp, false, false>(ptr_k, gamma_k, residual_k_ptr, head_size, eps, input_vec_k);
        } else {
            apply_rmsnorm<T_ACC, scalar_t, vec_size, block_size, num_warp, false, false>(ptr_k, gamma_k, head_size, eps, input_vec_k);
        }
        __shared__ scalar_t k_smem[head_size * num_warp];
#pragma unroll
        for (int i = 0; i < vec_size; i++) {
            k_smem[idx + i] = input_vec_k[i];
        }
        __syncthreads();
        scalar_t output_k[vec_size];
        apply_rope_vec<scalar_t, vec_size>(input_vec_k, output_k, k_smem, smem_cos, smem_sin, idx, half_rd);
        *(LoadT*)(ptr_k + idx) = *(LoadT*)output_k;
    }
}

} // namespace

void fuse_rms_mrope(
    torch::Tensor& q,
    torch::Tensor& k,
    const torch::Tensor& cos,
    const torch::Tensor& sin,
    const std::vector<int64_t>& mrope_section,
    int64_t head_size,
    bool is_interleaved,
    const torch::Tensor& weight_q,
    const torch::Tensor& weight_k,
    const torch::optional<torch::Tensor>& residual_q,
    const torch::optional<torch::Tensor>& residual_k,
    double epsilon) {
    const int64_t rotary_dim = head_size;
    TORCH_CHECK(head_size == 64 || head_size == 128,
                "fuse_rms_mrope only supports head_size 64 or 128");
    TORCH_CHECK(epsilon > 0.0, "fuse_rms_mrope: epsilon must be positive, got ", epsilon);
    TORCH_CHECK(q.dim() == 2 && k.dim() == 2,
                "fuse_rms_mrope: q and k must be 2D [num_tokens, num_heads * head_size]");
    TORCH_CHECK(q.size(0) == k.size(0),
                "fuse_rms_mrope: q and k must have the same num_tokens, got ",
                q.size(0), " vs ", k.size(0));
    TORCH_CHECK(q.size(1) > 0 && q.size(1) % head_size == 0,
                "fuse_rms_mrope: q.size(1)=", q.size(1),
                " must be positive and divisible by head_size=", head_size);
    TORCH_CHECK(k.size(1) > 0 && k.size(1) % head_size == 0,
                "fuse_rms_mrope: k.size(1)=", k.size(1),
                " must be positive and divisible by head_size=", head_size);

    const int64_t num_tokens = q.size(0);
    const int64_t n_qh = q.size(1) / head_size;
    const int64_t n_kh = k.size(1) / head_size;
    const int64_t half_rd = rotary_dim / 2;

    TORCH_CHECK(mrope_section.size() == 3,
                "fuse_rms_mrope: mrope_section must have 3 elements [t, h, w]");
    const int64_t mrope_section_t = mrope_section[0];
    const int64_t mrope_section_h = mrope_section[1];
    const int64_t mrope_section_w = mrope_section[2];
    TORCH_CHECK(mrope_section_t >= 0 && mrope_section_h >= 0 && mrope_section_w >= 0 &&
                    mrope_section_t + mrope_section_h + mrope_section_w == half_rd,
                "fuse_rms_mrope: mrope_section must be non-negative and sum to head_size/2=",
                half_rd, ", got [", mrope_section_t, ", ", mrope_section_h, ", ",
                mrope_section_w, "]");

    TORCH_CHECK(cos.sizes() == torch::IntArrayRef({3, num_tokens, half_rd}) &&
                    sin.sizes() == torch::IntArrayRef({3, num_tokens, half_rd}),
                "fuse_rms_mrope: cos/sin must be [3, num_tokens, head_size/2]=[",
                3, ", ", num_tokens, ", ", half_rd, "], got cos=", cos.sizes(),
                ", sin=", sin.sizes());
    TORCH_CHECK(weight_q.sizes() == torch::IntArrayRef({head_size}) &&
                    weight_k.sizes() == torch::IntArrayRef({head_size}),
                "fuse_rms_mrope: weight_q/weight_k must be 1D [head_size]=[", head_size,
                "], got weight_q=", weight_q.sizes(), ", weight_k=", weight_k.sizes());

    TORCH_CHECK(q.scalar_type() == at::kHalf || q.scalar_type() == at::kBFloat16 ||
                    q.scalar_type() == at::kFloat || q.scalar_type() == at::kDouble,
                "fuse_rms_mrope: unsupported dtype ", q.scalar_type());
    TORCH_CHECK(k.scalar_type() == q.scalar_type() &&
                    cos.scalar_type() == q.scalar_type() &&
                    sin.scalar_type() == q.scalar_type() &&
                    weight_q.scalar_type() == q.scalar_type() &&
                    weight_k.scalar_type() == q.scalar_type(),
                "fuse_rms_mrope: q/k/cos/sin/weight_q/weight_k must share the same dtype");
    TORCH_CHECK(q.is_contiguous() && k.is_contiguous() && cos.is_contiguous() &&
                    sin.is_contiguous() && weight_q.is_contiguous() &&
                    weight_k.is_contiguous(),
                "fuse_rms_mrope: q/k/cos/sin/weight_q/weight_k must be contiguous");

    TORCH_CHECK(residual_q.has_value() == residual_k.has_value(),
                "fuse_rms_mrope: residual_q and residual_k must both be provided or both omitted");
    if (residual_q.has_value()) {
        const torch::Tensor& rq = *residual_q;
        const torch::Tensor& rk = *residual_k;
        TORCH_CHECK(rq.sizes() == q.sizes() && rk.sizes() == k.sizes(),
                    "fuse_rms_mrope: residual_q/k must match q/k shapes");
        TORCH_CHECK(rq.device() == q.device() && rk.device() == q.device(),
                    "fuse_rms_mrope: residual_q/k must be on the same device as q");
        TORCH_CHECK(rq.scalar_type() == q.scalar_type() && rk.scalar_type() == q.scalar_type(),
                    "fuse_rms_mrope: residual_q/k must have the same dtype as q");
    }

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(q.device());
    const hipStream_t stream = at::hip::getCurrentHIPStream();

    const int mrope_section_t_i = static_cast<int>(mrope_section_t);
    const int mrope_section_h_i = static_cast<int>(mrope_section_h);
    const int mrope_section_w_i = static_cast<int>(mrope_section_w);
    const int num_tokens_i = static_cast<int>(num_tokens);
    const int n_qh_i = static_cast<int>(n_qh);
    const int n_kh_i = static_cast<int>(n_kh);

#define LAUNCH_MROTARY_KERNEL(is_interleaved, RESIDUAL, num_warp, head_size, block_size) \
    fuse_rms_mrope_kernel_optimized<T_ACC, scalar_t, is_interleaved, RESIDUAL, vec_size, num_warp, head_size, block_size> \
        <<<grid, block_size, shared_mem_size, stream>>>( \
            q.data_ptr<scalar_t>(), k.data_ptr<scalar_t>(), cos.data_ptr<scalar_t>(), sin.data_ptr<scalar_t>(), \
            num_tokens_i, n_qh_i, n_kh_i, static_cast<int>(rotary_dim), \
            mrope_section_t_i, mrope_section_h_i, mrope_section_w_i, \
            weight_q.data_ptr<scalar_t>(), weight_k.data_ptr<scalar_t>(), \
            residual_q.has_value() ? residual_q->data_ptr<scalar_t>() : nullptr, \
            residual_k.has_value() ? residual_k->data_ptr<scalar_t>() : nullptr, epsilon);

#define LAUNCH_MROTARY_KERNEL_PIPELINE(is_interleaved, RESIDUAL, num_warp, head_size, block_size) \
    fuse_rms_mrope_kernel_optimized_pipeline<T_ACC, scalar_t, is_interleaved, RESIDUAL, vec_size, num_warp, head_size, block_size> \
        <<<grid, block_size, shared_mem_size, stream>>>( \
            q.data_ptr<scalar_t>(), k.data_ptr<scalar_t>(), cos.data_ptr<scalar_t>(), sin.data_ptr<scalar_t>(), \
            num_tokens_i, n_qh_i, n_kh_i, static_cast<int>(rotary_dim), \
            mrope_section_t_i, mrope_section_h_i, mrope_section_w_i, \
            weight_q.data_ptr<scalar_t>(), weight_k.data_ptr<scalar_t>(), \
            residual_q.has_value() ? residual_q->data_ptr<scalar_t>() : nullptr, \
            residual_k.has_value() ? residual_k->data_ptr<scalar_t>() : nullptr, epsilon);

#define LAUNCH_MROTARY_KERNEL_SMALL(is_interleaved, RESIDUAL, num_warp, head_size, block_size) \
    fuse_rms_mrope_kernel_optimized_small<T_ACC, scalar_t, is_interleaved, RESIDUAL, vec_size, num_warp, head_size, block_size> \
        <<<grid, block_size, shared_mem_size, stream>>>( \
            q.data_ptr<scalar_t>(), k.data_ptr<scalar_t>(), cos.data_ptr<scalar_t>(), sin.data_ptr<scalar_t>(), \
            num_tokens_i, n_qh_i, n_kh_i, static_cast<int>(rotary_dim), \
            mrope_section_t_i, mrope_section_h_i, mrope_section_w_i, \
            weight_q.data_ptr<scalar_t>(), weight_k.data_ptr<scalar_t>(), \
            residual_q.has_value() ? residual_q->data_ptr<scalar_t>() : nullptr, \
            residual_k.has_value() ? residual_k->data_ptr<scalar_t>() : nullptr, epsilon);

    AT_DISPATCH_FLOATING_TYPES_AND2(at::ScalarType::Half, at::ScalarType::BFloat16, q.scalar_type(), "fuse_rms_mrope", [&] {
        using T_ACC = at::acc_type<scalar_t, true>;
        int shared_mem_size = (rotary_dim / 2) * 2 * sizeof(scalar_t);
        bool is_mul = (n_qh_i % n_kh_i == 0);
        if (num_tokens_i <= 256) {
            if (head_size == 128 && is_mul && n_kh_i % 4 == 0) {
                constexpr int num_warp = 4;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 2;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, true, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, true, num_warp, 128, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, false, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, false, num_warp, 128, block_size);
                    }
                }
            } else if (head_size == 128 && is_mul && n_kh_i % 3 == 0) {
                constexpr int num_warp = 3;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 2;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, true, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, true, num_warp, 128, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, false, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, false, num_warp, 128, block_size);
                    }
                }
            } else if (head_size == 128 && is_mul && n_kh_i % 2 == 0) {
                constexpr int num_warp = 2;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 2;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, true, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, true, num_warp, 128, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, false, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, false, num_warp, 128, block_size);
                    }
                }
            } else if (head_size == 128 && is_mul && n_qh_i % 3 == 0 && n_kh_i == 1) {
                constexpr int num_warp = 4;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 2;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(true, true, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(false, true, num_warp, 128, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(true, false, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(false, false, num_warp, 128, block_size);
                    }
                }
            } else if (head_size == 128 && is_mul && n_qh_i % 2 == 0 && n_kh_i == 1) {
                constexpr int num_warp = 3;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 2;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(true, true, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(false, true, num_warp, 128, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(true, false, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(false, false, num_warp, 128, block_size);
                    }
                }
            } else if (head_size == 128) {
                constexpr int num_warp = 1;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 2;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, true, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, true, num_warp, 128, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, false, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, false, num_warp, 128, block_size);
                    }
                }
            } else if (head_size == 64 && is_mul && n_kh_i % 4 == 0) {
                constexpr int num_warp = 4;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 1;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, true, num_warp, 64, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, true, num_warp, 64, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, false, num_warp, 64, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, false, num_warp, 64, block_size);
                    }
                }
            } else if (head_size == 64 && is_mul && n_kh_i % 2 == 0) {
                constexpr int num_warp = 2;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 1;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, true, num_warp, 64, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, true, num_warp, 64, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, false, num_warp, 64, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, false, num_warp, 64, block_size);
                    }
                }
            } else if (head_size == 64 && n_kh_i % 1 == 0) {
                constexpr int num_warp = 1;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 1;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, true, num_warp, 64, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, true, num_warp, 64, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_SMALL(true, false, num_warp, 64, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_SMALL(false, false, num_warp, 64, block_size);
                    }
                }
            }
        } else {
            if (head_size == 128 && is_mul && n_kh_i % 4 == 0) {
                constexpr int num_warp = 4;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 2;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, true, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, true, num_warp, 128, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, false, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, false, num_warp, 128, block_size);
                    }
                }
            } else if (head_size == 128 && is_mul && n_kh_i % 3 == 0) {
                constexpr int num_warp = 3;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 2;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, true, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, true, num_warp, 128, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, false, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, false, num_warp, 128, block_size);
                    }
                }
            } else if (head_size == 128 && is_mul && n_kh_i % 2 == 0) {
                constexpr int num_warp = 2;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 2;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, true, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, true, num_warp, 128, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, false, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, false, num_warp, 128, block_size);
                    }
                }
            } else if (head_size == 128 && is_mul && n_qh_i % 3 == 0 && n_kh_i == 1) {
                constexpr int num_warp = 4;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 2;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(true, true, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(false, true, num_warp, 128, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(true, false, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(false, false, num_warp, 128, block_size);
                    }
                }
            } else if (head_size == 128 && is_mul && n_qh_i % 2 == 0 && n_kh_i == 1) {
                constexpr int num_warp = 3;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 2;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(true, true, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(false, true, num_warp, 128, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(true, false, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL_PIPELINE(false, false, num_warp, 128, block_size);
                    }
                }
            } else if (head_size == 128) {
                constexpr int num_warp = 1;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 2;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, true, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, true, num_warp, 128, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, false, num_warp, 128, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, false, num_warp, 128, block_size);
                    }
                }
            } else if (head_size == 64 && is_mul && n_kh_i % 4 == 0) {
                constexpr int num_warp = 4;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 1;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, true, num_warp, 64, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, true, num_warp, 64, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, false, num_warp, 64, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, false, num_warp, 64, block_size);
                    }
                }
            } else if (head_size == 64 && is_mul && n_kh_i % 2 == 0) {
                constexpr int num_warp = 2;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 1;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, true, num_warp, 64, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, true, num_warp, 64, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, false, num_warp, 64, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, false, num_warp, 64, block_size);
                    }
                }
            } else if (head_size == 64 && n_kh_i % 1 == 0) {
                constexpr int num_warp = 1;
                constexpr int block_size = num_warp * 64;
                constexpr int vec_size = 1;
                dim3 grid(num_tokens_i);
                dim3 block(block_size);
                if (residual_q.has_value() && residual_k.has_value()) {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, true, num_warp, 64, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, true, num_warp, 64, block_size);
                    }
                } else {
                    if (is_interleaved) {
                        LAUNCH_MROTARY_KERNEL(true, false, num_warp, 64, block_size);
                    } else {
                        LAUNCH_MROTARY_KERNEL(false, false, num_warp, 64, block_size);
                    }
                }
            }
        }
    });
}

} // namespace aiter

PYBIND11_MODULE(TORCH_EXTENSION_NAME, m)
{
   FUSE_RMS_MROPE_PYBIND;
}
