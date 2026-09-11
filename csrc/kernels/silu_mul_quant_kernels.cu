// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
// SPDX-License-Identifier: Apache-2.0

#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <ATen/native/hip/MemoryAccess.cuh>
#include <torch/extension.h>

#include <cmath>
#include <optional>

#include "activation.h"

namespace aiter {

namespace {

constexpr int WARP_SIZE = 64; 

// ---------------------------------------------------------------------------
// math helpers
// ---------------------------------------------------------------------------

__device__ __forceinline__ int8_t float_to_int8_rn(float x)
{
    constexpr float i8_min = static_cast<float>(INT8_MIN);
    constexpr float i8_max = static_cast<float>(INT8_MAX);

    // nearbyint uses the current rounding mode, which is always
    // FE_TONEAREST on HIP, matching CUDA's cvt.rni.
    float dst = std::nearbyint(x);
    dst       = (dst < i8_min) ? i8_min : (dst > i8_max) ? i8_max : dst;
    return static_cast<int8_t>(dst);
}

template <typename T>
__device__ __forceinline__ T silu_kernel(const T& x)
{
    constexpr float LOG2E = 1.44269504088896340736f;
    return static_cast<T>(static_cast<float>(x) /
                          (1.0f + __builtin_amdgcn_exp2f(-static_cast<float>(x) * LOG2E)));
}

template <typename scalar_t, bool act_first>
__device__ __forceinline__ float silu_mul(const scalar_t& x, const scalar_t& y)
{
    return act_first ? static_cast<float>(silu_kernel(x)) * static_cast<float>(y)
                     : static_cast<float>(x) * static_cast<float>(silu_kernel(y));
}

template <typename T, int BLOCK>
__device__ __forceinline__ T block_reduce_max(T val, T* shared)
{
    constexpr int share_size = BLOCK / WARP_SIZE;
#pragma unroll
    for(int offset = WARP_SIZE / 2; offset > 0; offset >>= 1)
    {
        val = fmaxf(val, __shfl_down(val, offset));
    }
    if constexpr(BLOCK == WARP_SIZE)
    {
        return val;
    }
    else
    {
        const int lid = threadIdx.x % WARP_SIZE;
        const int wid = threadIdx.x / WARP_SIZE;
        if(lid == 0 && wid < share_size)
            shared[wid] = val;
        __syncthreads();
        if(wid == 0 && lid < share_size)
        {
            val = shared[lid];
#pragma unroll
            for(int offset = share_size / 2; offset > 0; offset >>= 1)
                val = fmaxf(val, __shfl_down(val, offset));
        }
        return val;
    }
}

// ---------------------------------------------------------------------------
// fp8 conversion (software path, round-to-nearest-even + saturate)
// ---------------------------------------------------------------------------

__device__ __forceinline__ uint8_t float_to_fp8e4m3(float f)
{
    constexpr uint32_t fp8_max    = UINT32_C(1087) << 20;
    constexpr uint32_t denorm_mask = UINT32_C(141) << 23;
    uint32_t f_bits                = __builtin_bit_cast(uint32_t, f);
    uint8_t result                 = 0u;
    const uint32_t sign            = f_bits & UINT32_C(0x80000000);
    f_bits ^= sign;
    if(f_bits >= fp8_max)
    {
        result = UINT8_C(0x7e);
    }
    else
    {
        if(f_bits < (UINT32_C(121) << 23))
        {
            f_bits = __builtin_bit_cast(
                uint32_t, __builtin_bit_cast(float, f_bits) + __builtin_bit_cast(float, denorm_mask));
            result = static_cast<uint8_t>(f_bits - denorm_mask);
        }
        else
        {
            uint8_t mant_odd = (f_bits >> 20) & 1;
            f_bits += ((uint32_t)(7 - 127) << 23) + 0xFFFFF;
            f_bits += mant_odd;
            result = static_cast<uint8_t>(f_bits >> 20);
            if(result > UINT8_C(0x7e))
                result = UINT8_C(0x7e);
        }
    }
    result |= static_cast<uint8_t>(sign >> 24);
    return result;
}

__device__ __forceinline__ uint8_t float_to_fp8e5m2(float f)
{
    constexpr uint32_t fp8_max    = UINT32_C(143) << 23;
    constexpr uint32_t denorm_mask = UINT32_C(134) << 23;
    constexpr uint32_t fp32_inf    = UINT32_C(255) << 23;
    uint32_t f_bits                = __builtin_bit_cast(uint32_t, f);
    uint8_t result                 = 0u;
    const uint32_t sign            = f_bits & UINT32_C(0x80000000);
    f_bits ^= sign;
    if(f_bits >= fp8_max)
    {
        result = f_bits > fp32_inf ? UINT8_C(0x7F) : UINT8_C(0x7C);
    }
    else
    {
        if(f_bits < (UINT32_C(113) << 23))
        {
            f_bits = __builtin_bit_cast(
                uint32_t, __builtin_bit_cast(float, f_bits) + __builtin_bit_cast(float, denorm_mask));
            result = static_cast<uint8_t>(f_bits - denorm_mask);
        }
        else
        {
            uint32_t mant_odd = (f_bits >> 21) & 1;
            f_bits += ((uint32_t)(15 - 127) << 23) + 0xFFFFF;
            f_bits += mant_odd;
            result = static_cast<uint8_t>(f_bits >> 21);
        }
    }
    result |= static_cast<uint8_t>(sign >> 24);
    return result;
}

template <bool E4M3>
__device__ __forceinline__ uint32_t float_to_fp8_x4(float a, float b, float c, float d)
{
#if defined(__gfx938__)
    uint32_t res;
    if constexpr(E4M3)
    {
        res = __builtin_hcu_cvt_pk_fp8_f32(a, b, 0u, false);
        res = __builtin_hcu_cvt_pk_fp8_f32(c, d, res, true);
    }
    else
    {
        res = __builtin_hcu_cvt_pk_bf8_f32(a, b, 0u, false);
        res = __builtin_hcu_cvt_pk_bf8_f32(c, d, res, true);
    }
    return res;
#else
    uint32_t out;
    uint8_t* p = reinterpret_cast<uint8_t*>(&out);
    if constexpr(E4M3)
    {
        p[0] = float_to_fp8e4m3(a);
        p[1] = float_to_fp8e4m3(b);
        p[2] = float_to_fp8e4m3(c);
        p[3] = float_to_fp8e4m3(d);
    }
    else
    {
        p[0] = float_to_fp8e5m2(a);
        p[1] = float_to_fp8e5m2(b);
        p[2] = float_to_fp8e5m2(c);
        p[3] = float_to_fp8e5m2(d);
    }
    return out;
#endif
}

constexpr float fp8_type_max(bool e4m3) { return e4m3 ? 448.0f : 57344.0f; }

// ---------------------------------------------------------------------------
// Fused silu_and_mul + per-token quant kernels.
//
// MASK: 0 = none, 1 = num_local_tokens_tensor (clipped by topk), 2 = expert_ids
// LOOP: grid-stride over tokens
// ---------------------------------------------------------------------------

enum class QuantMask : int
{
    None = 0,
    NumLocalTokens,
    ExpertIds,
};

template <typename scalar_t,
          int VEC,
          int BLOCK,
          int MASK,
          bool LOOP,
          bool FP8>
__global__ void act_mul_quant_kernel(int64_t num_tokens,
                                     uint8_t* __restrict__ out, // int8 or fp8-as-uint8
                                     const scalar_t* __restrict__ input,
                                     float* __restrict__ scales,
                                     const int d,
                                     const int topk,
                                     const int fp8type,
                                     const int32_t* __restrict__ num_local_tokens,
                                     const int32_t* __restrict__ expert_ids)
{
    constexpr int share_size = BLOCK / WARP_SIZE;
    __shared__ float val_shared[share_size];
    __shared__ float s_token_scale;

    using VecType     = typename at::native::memory::aligned_vector<scalar_t, VEC>;
    using VecOutType  = typename at::native::memory::aligned_vector<uint8_t, VEC>;

    int64_t token_idx       = blockIdx.x;
    int64_t num_valid_tasks = num_tokens;
    if constexpr(MASK == static_cast<int>(QuantMask::NumLocalTokens))
    {
        if(num_local_tokens != nullptr)
        {
            num_valid_tasks = num_tokens;
            if(num_valid_tasks >= static_cast<int64_t>(num_local_tokens[0]) * topk)
                num_valid_tasks = static_cast<int64_t>(num_local_tokens[0]) * topk;
            if(token_idx >= num_valid_tasks)
                return;
        }
    }
    else if constexpr(MASK == static_cast<int>(QuantMask::ExpertIds))
    {
        if(expert_ids != nullptr && expert_ids[token_idx] == -1)
            return;
    }

    do
    {
        const int64_t input_offset  = token_idx * 2 * d;
        const int64_t output_offset = token_idx * d;

        const int idx   = threadIdx.x * VEC;
        float r_y[VEC];

        float row_max = 0.f;
        if(idx < d)
        {
            scalar_t r_x1[VEC];
            scalar_t r_x2[VEC];
            *(VecType*)r_x1 = *(VecType*)(input + input_offset + idx);
            *(VecType*)r_x2 = *(VecType*)(input + input_offset + d + idx);
#pragma unroll
            for(int i = 0; i < VEC; i++)
                r_y[i] = silu_mul<scalar_t, true>(r_x1[i], r_x2[i]);
#pragma unroll
            for(int i = 0; i < VEC; i++)
                row_max = fmaxf(row_max, fabsf(r_y[i]));
        }

        row_max = block_reduce_max<float, BLOCK>(row_max, val_shared);
        if(threadIdx.x == 0)
        {
            if constexpr(FP8)
            {
                const float max_v       = fp8_type_max(fp8type == 0);
                const float min_scaling = 1.0f / (max_v * 512.0f);
                s_token_scale           = fmaxf(row_max / max_v, min_scaling);
            }
            else
            {
                s_token_scale = row_max;
            }
            scales[token_idx] = FP8 ? s_token_scale : s_token_scale / 127.f;
        }
        __syncthreads();

        float inv_s;
        if constexpr(FP8)
        {
            inv_s = 1.0f / s_token_scale;
        }
        else
        {
            inv_s = (s_token_scale == 0.f) ? 0.f : 127.f / s_token_scale;
        }

        if(idx < d)
        {
            uint8_t out_buf[VEC];
            if constexpr(FP8)
            {
                if constexpr(VEC % 4 == 0)
                {
#pragma unroll
                    for(int i = 0; i < VEC; i += 4)
                        *reinterpret_cast<uint32_t*>(&out_buf[i]) =
                            (fp8type == 0)
                                ? float_to_fp8_x4<true>(r_y[i] * inv_s, r_y[i + 1] * inv_s,
                                                        r_y[i + 2] * inv_s, r_y[i + 3] * inv_s)
                                : float_to_fp8_x4<false>(r_y[i] * inv_s, r_y[i + 1] * inv_s,
                                                         r_y[i + 2] * inv_s, r_y[i + 3] * inv_s);
                }
                else
                {
#pragma unroll
                    for(int i = 0; i < VEC; i++)
                        out_buf[i] = (fp8type == 0) ? float_to_fp8e4m3(r_y[i] * inv_s)
                                                    : float_to_fp8e5m2(r_y[i] * inv_s);
                }
            }
            else
            {
#pragma unroll
                for(int i = 0; i < VEC; i++)
                    reinterpret_cast<int8_t*>(&out_buf)[i] = float_to_int8_rn(r_y[i] * inv_s);
            }
            *(VecOutType*)(out + output_offset + idx) = *(VecOutType*)out_buf;
        }

        if constexpr(LOOP)
        {
            if constexpr(MASK == static_cast<int>(QuantMask::ExpertIds))
            {
                break; 
            }
            token_idx += gridDim.x;
            __syncthreads(); // protect shared-memory reuse across iterations
        }
        else
        {
            break;
        }
    } while(token_idx < num_valid_tasks);
}

// Non-vectorized fallback (d > 32768 or d not aligned), same mask/loop
// semantics as the vectorized kernel.
template <typename scalar_t,
          int BLOCK,
          int MASK,
          bool LOOP,
          bool FP8>
__global__ void act_mul_quant_kernel_generic(int64_t num_tokens,
                                             uint8_t* __restrict__ out,
                                             const scalar_t* __restrict__ input,
                                             float* __restrict__ scales,
                                             const int d,
                                             const int topk,
                                             const int fp8type,
                                             const int32_t* __restrict__ num_local_tokens,
                                             const int32_t* __restrict__ expert_ids)
{
    constexpr int share_size = BLOCK / WARP_SIZE;
    __shared__ float shared_mem[share_size];
    __shared__ float s_token_scale;

    int64_t token_idx       = blockIdx.x;
    int64_t num_valid_tasks = num_tokens;
    if constexpr(MASK == static_cast<int>(QuantMask::NumLocalTokens))
    {
        if(num_local_tokens != nullptr)
        {
            num_valid_tasks = num_tokens;
            if(num_valid_tasks >= static_cast<int64_t>(num_local_tokens[0]) * topk)
                num_valid_tasks = static_cast<int64_t>(num_local_tokens[0]) * topk;
            if(token_idx >= num_valid_tasks)
                return;
        }
    }
    else if constexpr(MASK == static_cast<int>(QuantMask::ExpertIds))
    {
        if(expert_ids != nullptr && expert_ids[token_idx] == -1)
            return;
    }

    do
    {
        const int64_t input_offset  = token_idx * 2 * d;
        const int64_t output_offset = token_idx * d;

        float row_max = 0.f;
        for(int64_t idx = threadIdx.x; idx < d; idx += BLOCK)
        {
            const scalar_t x = input[input_offset + idx];
            const scalar_t y = input[input_offset + d + idx];
            row_max = fmaxf(row_max, fabsf(silu_mul<scalar_t, true>(x, y)));
        }

        row_max = block_reduce_max<float, BLOCK>(row_max, shared_mem);
        if(threadIdx.x == 0)
        {
            if constexpr(FP8)
            {
                const float max_v       = fp8_type_max(fp8type == 0);
                const float min_scaling = 1.0f / (max_v * 512.0f);
                s_token_scale           = fmaxf(row_max / max_v, min_scaling);
            }
            else
            {
                s_token_scale = row_max;
            }
            scales[token_idx] = FP8 ? s_token_scale : s_token_scale / 127.f;
        }
        __syncthreads();

        float inv_s;
        if constexpr(FP8)
        {
            inv_s = 1.0f / s_token_scale;
        }
        else
        {
            inv_s = (s_token_scale == 0.f) ? 0.f : 127.f / s_token_scale;
        }

        for(int64_t idx = threadIdx.x; idx < d; idx += BLOCK)
        {
            const scalar_t x = input[input_offset + idx];
            const scalar_t y = input[input_offset + d + idx];
            const float val  = silu_mul<scalar_t, true>(x, y);
            if constexpr(FP8)
            {
                out[output_offset + idx] =
                    (fp8type == 0) ? float_to_fp8e4m3(val * inv_s) : float_to_fp8e5m2(val * inv_s);
            }
            else
            {
                reinterpret_cast<int8_t*>(out)[output_offset + idx] = float_to_int8_rn(val * inv_s);
            }
        }

        if constexpr(LOOP)
        {
            if constexpr(MASK == static_cast<int>(QuantMask::ExpertIds))
            {
                break;
            }
            token_idx += gridDim.x;
        }
        else
        {
            break;
        }
    } while(token_idx < num_valid_tasks);
}

// EP layout, token-major: one token per block (grid.x = E * T). The previous
// grid=(E,128) + gridDim.y-stride design serialized each block over several
// tokens behind a per-iteration tokens_per_expert load + barriers, and
// duplicated work 128/T x whenever T < 128; both are gone here.
template <typename scalar_t, int VEC, int BLOCK, bool FP8>
__global__ void act_mul_quant_ep_kernel(int64_t num_tokens,
                                        uint8_t* __restrict__ out,
                                        const scalar_t* __restrict__ input,
                                        float* __restrict__ scales,
                                        const int d,
                                        const int fp8type,
                                        const int32_t tokens_per_expert_dim,
                                        const int32_t* __restrict__ tokens_per_expert)
{
    constexpr int share_size = BLOCK / WARP_SIZE;
    __shared__ float val_shared[share_size];
    __shared__ float s_token_scale;

    using VecType    = typename at::native::memory::aligned_vector<scalar_t, VEC>;
    using VecOutType = typename at::native::memory::aligned_vector<uint8_t, VEC>;

    const int64_t token_idx = blockIdx.x;
    if(token_idx >= num_tokens)
        return;
    if(tokens_per_expert != nullptr)
    {
        const int32_t e = static_cast<int32_t>(token_idx / tokens_per_expert_dim);
        const int32_t t = static_cast<int32_t>(token_idx % tokens_per_expert_dim);
        if(t >= tokens_per_expert[e])
            return;
    }

    {
        const int idx = threadIdx.x * VEC;
        const int64_t input_offset  = token_idx * 2 * d;
        const int64_t output_offset = token_idx * d;

        float r_y[VEC];
        float row_max = 0.f;
        if(idx < d)
        {
            scalar_t r_x1[VEC];
            scalar_t r_x2[VEC];
            *(VecType*)r_x1 = *(VecType*)(input + input_offset + idx);
            *(VecType*)r_x2 = *(VecType*)(input + input_offset + d + idx);
#pragma unroll
            for(int i = 0; i < VEC; i++)
                r_y[i] = silu_mul<scalar_t, true>(r_x1[i], r_x2[i]);
#pragma unroll
            for(int i = 0; i < VEC; i++)
                row_max = fmaxf(row_max, fabsf(r_y[i]));
        }

        row_max = block_reduce_max<float, BLOCK>(row_max, val_shared);
        if(threadIdx.x == 0)
        {
            if constexpr(FP8)
            {
                const float max_v       = fp8_type_max(fp8type == 0);
                const float min_scaling = 1.0f / (max_v * 512.0f);
                s_token_scale           = fmaxf(row_max / max_v, min_scaling);
            }
            else
            {
                s_token_scale = row_max;
            }
            scales[token_idx] = FP8 ? s_token_scale : s_token_scale / 127.f;
        }
        __syncthreads();

        float inv_s;
        if constexpr(FP8)
        {
            inv_s = 1.0f / s_token_scale;
        }
        else
        {
            inv_s = (s_token_scale == 0.f) ? 0.f : 127.f / s_token_scale;
        }

        if(idx < d)
        {
            uint8_t out_buf[VEC];
            if constexpr(FP8)
            {
                if constexpr(VEC % 4 == 0)
                {
#pragma unroll
                    for(int i = 0; i < VEC; i += 4)
                        *reinterpret_cast<uint32_t*>(&out_buf[i]) =
                            (fp8type == 0)
                                ? float_to_fp8_x4<true>(r_y[i] * inv_s, r_y[i + 1] * inv_s,
                                                        r_y[i + 2] * inv_s, r_y[i + 3] * inv_s)
                                : float_to_fp8_x4<false>(r_y[i] * inv_s, r_y[i + 1] * inv_s,
                                                         r_y[i + 2] * inv_s, r_y[i + 3] * inv_s);
                }
                else
                {
#pragma unroll
                    for(int i = 0; i < VEC; i++)
                        out_buf[i] = (fp8type == 0) ? float_to_fp8e4m3(r_y[i] * inv_s)
                                                    : float_to_fp8e5m2(r_y[i] * inv_s);
                }
            }
            else
            {
#pragma unroll
                for(int i = 0; i < VEC; i++)
                    reinterpret_cast<int8_t*>(&out_buf)[i] = float_to_int8_rn(r_y[i] * inv_s);
            }
            *(VecOutType*)(out + output_offset + idx) = *(VecOutType*)out_buf;
        }
    }
}

template <typename scalar_t, int BLOCK, bool FP8>
__global__ void act_mul_quant_ep_kernel_generic(int64_t num_tokens,
                                                uint8_t* __restrict__ out,
                                                const scalar_t* __restrict__ input,
                                                float* __restrict__ scales,
                                                const int d,
                                                const int fp8type,
                                                const int32_t tokens_per_expert_dim,
                                                const int32_t* __restrict__ tokens_per_expert)
{
    constexpr int share_size = BLOCK / WARP_SIZE;
    __shared__ float shared_mem[share_size];
    __shared__ float s_token_scale;

    const int64_t token_idx = blockIdx.x;
    if(token_idx >= num_tokens)
        return;
    if(tokens_per_expert != nullptr)
    {
        const int32_t e = static_cast<int32_t>(token_idx / tokens_per_expert_dim);
        const int32_t t = static_cast<int32_t>(token_idx % tokens_per_expert_dim);
        if(t >= tokens_per_expert[e])
            return;
    }

    const int64_t input_offset  = token_idx * 2 * d;
    const int64_t output_offset = token_idx * d;

        float row_max = 0.f;
        for(int64_t idx = threadIdx.x; idx < d; idx += BLOCK)
        {
            const scalar_t x = input[input_offset + idx];
            const scalar_t y = input[input_offset + d + idx];
            row_max = fmaxf(row_max, fabsf(silu_mul<scalar_t, true>(x, y)));
        }

        row_max = block_reduce_max<float, BLOCK>(row_max, shared_mem);
        if(threadIdx.x == 0)
        {
            if constexpr(FP8)
            {
                const float max_v       = fp8_type_max(fp8type == 0);
                const float min_scaling = 1.0f / (max_v * 512.0f);
                s_token_scale           = fmaxf(row_max / max_v, min_scaling);
            }
            else
            {
                s_token_scale = row_max;
            }
            scales[token_idx] = FP8 ? s_token_scale : s_token_scale / 127.f;
        }
        __syncthreads();

        float inv_s;
        if constexpr(FP8)
        {
            inv_s = 1.0f / s_token_scale;
        }
        else
        {
            inv_s = (s_token_scale == 0.f) ? 0.f : 127.f / s_token_scale;
        }

        for(int64_t idx = threadIdx.x; idx < d; idx += BLOCK)
        {
            const scalar_t x = input[input_offset + idx];
            const scalar_t y = input[input_offset + d + idx];
            const float val  = silu_mul<scalar_t, true>(x, y);
            if constexpr(FP8)
            {
                out[output_offset + idx] =
                    (fp8type == 0) ? float_to_fp8e4m3(val * inv_s) : float_to_fp8e5m2(val * inv_s);
            }
            else
            {
                reinterpret_cast<int8_t*>(out)[output_offset + idx] = float_to_int8_rn(val * inv_s);
            }
        }
}

// ---------------------------------------------------------------------------
// masked (non-quant) EP activation: silu_and_mul over [E, T, H] with
// mask_m[E] valid-token counts.
// ---------------------------------------------------------------------------

template <typename scalar_t, int VEC>
__global__ void silu_and_mul_ep_kernel(scalar_t* __restrict__ output,
                                       const scalar_t* __restrict__ input,
                                       const int32_t* __restrict__ mask_m,
                                       int64_t d,
                                       int64_t tokens_per_expert)
{
    using VecType = typename at::native::memory::aligned_vector<scalar_t, VEC>;

    const int64_t expert_idx = blockIdx.x;
    for(int64_t token_in_expert = blockIdx.y; token_in_expert < tokens_per_expert;
        token_in_expert += gridDim.y)
    {
        if(token_in_expert >= mask_m[expert_idx])
            break;

        const int64_t token_idx = expert_idx * tokens_per_expert + token_in_expert;
        for(int64_t idx = static_cast<int64_t>(threadIdx.x) * VEC; idx < d;
            idx += static_cast<int64_t>(blockDim.x) * VEC)
        {
            const int64_t input_offset  = token_idx * 2 * d + idx;
            const int64_t output_offset = token_idx * d + idx;
            scalar_t r_x1[VEC];
            scalar_t r_x2[VEC];
            scalar_t r_y[VEC];
            *(VecType*)r_x1 = *(VecType*)(input + input_offset);
            *(VecType*)r_x2 = *(VecType*)(input + input_offset + d);
#pragma unroll
            for(int i = 0; i < VEC; ++i)
                r_y[i] = silu_kernel(r_x1[i]) * r_x2[i];
            *(VecType*)(output + output_offset) = *(VecType*)r_y;
        }
    }
}

// ---------------------------------------------------------------------------
// relu2: out = relu(x)^2
// ---------------------------------------------------------------------------

template <typename scalar_t>
__device__ __forceinline__ scalar_t squared_relu_kernel(const scalar_t& x)
{
    const float x_float = static_cast<float>(x);
    const float relu_val = x_float > 0.0f ? x_float : 0.0f;
    return static_cast<scalar_t>(relu_val * relu_val);
}

template <typename scalar_t>
__global__ void relu2_kernel(scalar_t* __restrict__ out,
                             const scalar_t* __restrict__ input,
                             const int d)
{
    const int64_t token_idx = blockIdx.x;
    for(int64_t idx = threadIdx.x; idx < d; idx += blockDim.x)
    {
        const int64_t offset = token_idx * d + idx;
        out[offset] = squared_relu_kernel(input[offset]);
    }
}

template <typename scalar_t, int VEC>
__global__ void relu2_kernel_vec(scalar_t* __restrict__ out,
                                 const scalar_t* __restrict__ input,
                                 const int d)
{
    using VecType = typename at::native::memory::aligned_vector<scalar_t, VEC>;

    const int64_t token_idx = blockIdx.x;
    const int idx           = threadIdx.x * VEC;
    if(idx < d)
    {
        const int64_t offset = token_idx * d + idx;
        scalar_t r_x[VEC];
        scalar_t r_y[VEC];
        *(VecType*)r_x = *(VecType*)(input + offset);
#pragma unroll
        for(int i = 0; i < VEC; i++)
            r_y[i] = squared_relu_kernel(r_x[i]);
        *(VecType*)(out + offset) = *(VecType*)r_y;
    }
}

template <typename scalar_t, int VEC, int D, int THREAD_PER_ROW, int ROWS_PER_BLOCK>
__launch_bounds__(1024, 1) __global__ void relu2_kernel_multirow(scalar_t* __restrict__ out,
                                                                 const scalar_t* __restrict__ input)
{
    using VecType = typename at::native::memory::aligned_vector<scalar_t, VEC>;

    const int t_row        = threadIdx.x / THREAD_PER_ROW;
    const int t_col        = threadIdx.x % THREAD_PER_ROW;
    const int64_t row      = static_cast<int64_t>(blockIdx.x) * ROWS_PER_BLOCK + t_row;
    const int64_t idx      = t_col * VEC;
    if(idx < D)
    {
        const int64_t offset = row * D + idx;
        scalar_t r_x[VEC];
        scalar_t r_y[VEC];
        *(VecType*)r_x = *(VecType*)(input + offset);
#pragma unroll
        for(int i = 0; i < VEC; i++)
            r_y[i] = squared_relu_kernel(r_x[i]);
        *(VecType*)(out + offset) = *(VecType*)r_y;
    }
}

// ---------------------------------------------------------------------------
// dispatch helpers
// ---------------------------------------------------------------------------

#define AITER_DISPATCH_FUSED_ACT_TYPES(TYPE, NAME, ...)                                        \
    AT_DISPATCH_SWITCH(TYPE, NAME,                                                             \
                       AT_DISPATCH_CASE(at::ScalarType::Float, __VA_ARGS__)                    \
                           AT_DISPATCH_CASE(at::ScalarType::Half, __VA_ARGS__)                 \
                               AT_DISPATCH_CASE(at::ScalarType::BFloat16, __VA_ARGS__))

// Base-address alignment gates for the vectorized dispatch buckets: bucket
// with vector width V requires input aligned to sizeof(scalar_t)*V and output
// aligned to V bytes.
struct VecAlign
{
    bool a2, a4, a8, a16, a32;
};

template <typename scalar_t>
VecAlign vec_align(const void* in, const void* out)
{
    const uintptr_t in_addr  = reinterpret_cast<uintptr_t>(in);
    const uintptr_t out_addr = reinterpret_cast<uintptr_t>(out);
    const uintptr_t esz      = sizeof(scalar_t);
    return {(in_addr % (esz * 2) == 0 && out_addr % 2 == 0),
            (in_addr % (esz * 4) == 0 && out_addr % 4 == 0),
            (in_addr % (esz * 8) == 0 && out_addr % 8 == 0),
            (in_addr % (esz * 16) == 0 && out_addr % 16 == 0),
            (in_addr % (esz * 32) == 0 && out_addr % 32 == 0)};
}

// d<=512 -> VEC2/256 (fp8: VEC4/128, packed x4 conversion needs VEC%4==0),
// d<=1024 -> 8/128, d<=2048 -> 8/256, d<=4096 -> 8/512, d<=8192 -> 8/1024,
// d<=16384 -> 16/1024, d<=32768 -> 32/1024, larger falls back to generic.
template <typename scalar_t, bool FP8>
void launch_act_mul_quant(int64_t num_tokens,
                          uint8_t* out_ptr,
                          const scalar_t* input_ptr,
                          float* scales_ptr,
                          int d,
                          int topk,
                          int fp8type,
                          const int32_t* num_local_tokens,
                          const int32_t* expert_ids,
                          int grid,
                          bool grid_stride, 
                          hipStream_t stream)
{
    constexpr int mask_nlt = static_cast<int>(QuantMask::NumLocalTokens);
    constexpr int mask_eids = static_cast<int>(QuantMask::ExpertIds);
    // vectorized loads require d to be a multiple of VEC; otherwise the
    // generic (non-vectorized) kernel is used. VEC16 doubles the per-thread
    // store width but halves the block size, which hurts latency-bound small
    // batches, so it is only selected when there are enough token blocks.
    const int min_vec = FP8 ? 4 : 2;
    const bool wide   = num_tokens >= 512;
    // vector accesses additionally require the buffer base addresses to be
    // aligned to the per-bucket vector width (contiguous slices of larger
    // buffers may be aligned to the element size only); a failed gate falls
    // through to the next narrower bucket, the generic kernel is the final
    // fallback
    const auto aln = vec_align<scalar_t>(input_ptr, out_ptr);

#define AITER_FUSED_SELECT(MASKV, LOOPV)                                                       \
    do                                                                                         \
    {                                                                                          \
        if(d <= 512 && d % min_vec == 0 && (FP8 ? aln.a4 : aln.a2))                                                                           \
        {                                                                                      \
            if constexpr(FP8)                                                                  \
                act_mul_quant_kernel<scalar_t, 4, 128, MASKV, LOOPV, FP8>                      \
                    <<<grid, 128, 0, stream>>>(num_tokens, out_ptr, input_ptr, scales_ptr, d,  \
                                               topk, fp8type, num_local_tokens, expert_ids);   \
            else                                                                               \
                act_mul_quant_kernel<scalar_t, 2, 256, MASKV, LOOPV, FP8>                      \
                    <<<grid, 256, 0, stream>>>(num_tokens, out_ptr, input_ptr, scales_ptr, d,  \
                                               topk, fp8type, num_local_tokens, expert_ids);   \
        }                                                                                      \
        else if(d <= 1024 && d % 8 == 0 && aln.a8)                                                                     \
            act_mul_quant_kernel<scalar_t, 8, 128, MASKV, LOOPV, FP8>                          \
                <<<grid, 128, 0, stream>>>(num_tokens, out_ptr, input_ptr, scales_ptr, d,      \
                                           topk, fp8type, num_local_tokens, expert_ids);       \
        else if(d <= 2048 && d % 16 == 0 && wide && aln.a16)                                                             \
            act_mul_quant_kernel<scalar_t, 16, 128, MASKV, LOOPV, FP8>                                         \
                <<<grid, 128, 0, stream>>>(num_tokens, out_ptr, input_ptr, scales_ptr, d,                      \
                                           topk, fp8type, num_local_tokens, expert_ids);       \
        else if(d <= 2048 && d % 8 == 0 && aln.a8)                                                                     \
            act_mul_quant_kernel<scalar_t, 8, 256, MASKV, LOOPV, FP8>                                          \
                <<<grid, 256, 0, stream>>>(num_tokens, out_ptr, input_ptr, scales_ptr, d,                      \
                                           topk, fp8type, num_local_tokens, expert_ids);       \
        else if(d <= 4096 && d % 16 == 0 && wide && aln.a16)                                                             \
            act_mul_quant_kernel<scalar_t, 16, 256, MASKV, LOOPV, FP8>                                         \
                <<<grid, 256, 0, stream>>>(num_tokens, out_ptr, input_ptr, scales_ptr, d,                      \
                                           topk, fp8type, num_local_tokens, expert_ids);       \
        else if(d <= 4096 && d % 8 == 0 && aln.a8)                                                                     \
            act_mul_quant_kernel<scalar_t, 8, 512, MASKV, LOOPV, FP8>                                          \
                <<<grid, 512, 0, stream>>>(num_tokens, out_ptr, input_ptr, scales_ptr, d,                      \
                                           topk, fp8type, num_local_tokens, expert_ids);       \
        else if(d <= 8192 && d % 16 == 0 && wide && aln.a16)                                                             \
            act_mul_quant_kernel<scalar_t, 16, 512, MASKV, LOOPV, FP8>                                         \
                <<<grid, 512, 0, stream>>>(num_tokens, out_ptr, input_ptr, scales_ptr, d,                      \
                                           topk, fp8type, num_local_tokens, expert_ids);       \
        else if(d <= 8192 && d % 8 == 0 && aln.a8)                                                                     \
            act_mul_quant_kernel<scalar_t, 8, 1024, MASKV, LOOPV, FP8>                                         \
                <<<grid, 1024, 0, stream>>>(num_tokens, out_ptr, input_ptr, scales_ptr, d,                     \
                                            topk, fp8type, num_local_tokens, expert_ids);      \
        else if(d <= 16384 && d % 16 == 0 && aln.a16)                                                                    \
            act_mul_quant_kernel<scalar_t, 16, 1024, MASKV, LOOPV, FP8>                        \
                <<<grid, 1024, 0, stream>>>(num_tokens, out_ptr, input_ptr, scales_ptr, d,     \
                                            topk, fp8type, num_local_tokens, expert_ids);      \
        else if(d <= 32768 && d % 32 == 0 && aln.a32)                                                                    \
            act_mul_quant_kernel<scalar_t, 32, 1024, MASKV, LOOPV, FP8>                        \
                <<<grid, 1024, 0, stream>>>(num_tokens, out_ptr, input_ptr, scales_ptr, d,     \
                                            topk, fp8type, num_local_tokens, expert_ids);      \
        else                                                                                   \
            act_mul_quant_kernel_generic<scalar_t, 1024, MASKV, LOOPV, FP8>                    \
                <<<grid, 1024, 0, stream>>>(num_tokens, out_ptr, input_ptr, scales_ptr, d,     \
                                            topk, fp8type, num_local_tokens, expert_ids);      \
    } while(0)

    if(expert_ids != nullptr)
    {
        AITER_FUSED_SELECT(mask_eids, false);
        return;
    }
    if(num_local_tokens != nullptr && grid_stride)
    {
        // grid-stride variant (grid possibly shrunk by expect_m / token count)
        AITER_FUSED_SELECT(mask_nlt, true);
        return;
    }
    AITER_FUSED_SELECT(mask_nlt, false);
#undef AITER_FUSED_SELECT
}

inline int fused_quant_grid(int64_t num_tokens,
                            bool has_num_local_tokens,
                            int topk,
                            int expert_m)
{
    int grid = static_cast<int>(num_tokens);
    if(has_num_local_tokens)
    {
        if(expert_m != -1)
        {
            grid = std::max(1, expert_m * topk);
        }
        else
        {
            if(num_tokens < 8192)
                grid = std::max<int64_t>(1, num_tokens);
            else if(num_tokens < 16384)
                grid = std::max<int64_t>(1, num_tokens / 4);
            else
                grid = std::max<int64_t>(1, num_tokens / 8);
        }
    }
    return grid;
}

} // anonymous namespace

// ---------------------------------------------------------------------------
// host APIs
// ---------------------------------------------------------------------------

void fuse_silu_mul_quant(torch::Tensor& out,             // [..., d] int8
                         torch::Tensor& input,           // [..., 2 * d]
                         torch::Tensor& scales,          // [..., 1] fp32
                         std::optional<torch::Tensor> num_local_tokens_tensor, // int32[1]
                         int64_t topk,
                         int64_t expect_m,
                         std::optional<torch::Tensor> expert_ids) // int32[...], -1 = pad
{
    TORCH_CHECK(input.is_contiguous(), "input must be contiguous");
    TORCH_CHECK(out.is_contiguous(), "out must be contiguous");
    TORCH_CHECK(out.scalar_type() == at::ScalarType::Char, "out must be int8");

    const int d              = input.size(-1) / 2;
    const int64_t num_tokens = input.numel() / input.size(-1);
    TORCH_CHECK(input.size(-1) % 2 == 0, "input's last dimension must be even");
    TORCH_CHECK(out.numel() == num_tokens * d, "out must have num_tokens * d elements");
    TORCH_CHECK(scales.is_contiguous(), "scales must be contiguous");
    TORCH_CHECK(scales.numel() >= num_tokens, "scales must cover num_tokens tokens");
    if(expert_ids.has_value())
        TORCH_CHECK(expert_ids->numel() >= num_tokens, "expert_ids must cover num_tokens tokens");
    if(num_local_tokens_tensor.has_value())
        TORCH_CHECK(num_local_tokens_tensor->numel() >= 1,
                    "num_local_tokens_tensor must be int32[1]");
    if(num_tokens == 0)
        return;

    const int grid = fused_quant_grid(num_tokens,
                                      num_local_tokens_tensor.has_value(),
                                      static_cast<int>(topk),
                                      static_cast<int>(expect_m));

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(input));
    const hipStream_t stream = at::hip::getCurrentHIPStream();

    const int32_t* nlt_ptr =
        num_local_tokens_tensor.has_value() ? num_local_tokens_tensor->data_ptr<int32_t>() : nullptr;
    const int32_t* eids_ptr =
        expert_ids.has_value() ? expert_ids->data_ptr<int32_t>() : nullptr;

    AITER_DISPATCH_FUSED_ACT_TYPES(input.scalar_type(), "fuse_silu_mul_quant", [&] {
        launch_act_mul_quant<scalar_t, false>(
            num_tokens,
            reinterpret_cast<uint8_t*>(out.data_ptr<int8_t>()),
            input.data_ptr<scalar_t>(),
            scales.data_ptr<float>(),
            d,
            static_cast<int>(topk),
            0,
            nlt_ptr,
            eids_ptr,
            grid,
            num_local_tokens_tensor.has_value() && (!(num_tokens < 8192) || expect_m != -1),
            stream);
    });
}

void fuse_silu_mul_fp8_quant(torch::Tensor& out,         // [..., d] fp8 (e4m3/e5m2)
                             torch::Tensor& input,       // [..., 2 * d]
                             torch::Tensor& scales,      // [..., 1] fp32
                             int64_t fp8type,            // 0 = e4m3, 1 = e5m2
                             std::optional<torch::Tensor> num_local_tokens_tensor,
                             int64_t topk,
                             int64_t expect_m,
                             std::optional<torch::Tensor> expert_ids)
{
    TORCH_CHECK(input.is_contiguous(), "input must be contiguous");
    TORCH_CHECK(out.is_contiguous(), "out must be contiguous");
    TORCH_CHECK(fp8type == 0 || fp8type == 1, "fp8type must be 0 (e4m3) or 1 (e5m2)");

    const int d              = input.size(-1) / 2;
    const int64_t num_tokens = input.numel() / input.size(-1);
    TORCH_CHECK(input.size(-1) % 2 == 0, "input's last dimension must be even");
    TORCH_CHECK(out.numel() == num_tokens * d, "out must have num_tokens * d elements");
    TORCH_CHECK(scales.is_contiguous(), "scales must be contiguous");
    TORCH_CHECK(scales.numel() >= num_tokens, "scales must cover num_tokens tokens");
    if(expert_ids.has_value())
        TORCH_CHECK(expert_ids->numel() >= num_tokens, "expert_ids must cover num_tokens tokens");
    if(num_local_tokens_tensor.has_value())
        TORCH_CHECK(num_local_tokens_tensor->numel() >= 1,
                    "num_local_tokens_tensor must be int32[1]");
    if(num_tokens == 0)
        return;

    const int grid = fused_quant_grid(num_tokens,
                                      num_local_tokens_tensor.has_value(),
                                      static_cast<int>(topk),
                                      static_cast<int>(expect_m));

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(input));
    const hipStream_t stream = at::hip::getCurrentHIPStream();

    const int32_t* nlt_ptr =
        num_local_tokens_tensor.has_value() ? num_local_tokens_tensor->data_ptr<int32_t>() : nullptr;
    const int32_t* eids_ptr =
        expert_ids.has_value() ? expert_ids->data_ptr<int32_t>() : nullptr;

    AITER_DISPATCH_FUSED_ACT_TYPES(input.scalar_type(), "fuse_silu_mul_fp8_quant", [&] {
        launch_act_mul_quant<scalar_t, true>(
            num_tokens,
            reinterpret_cast<uint8_t*>(out.data_ptr()),
            input.data_ptr<scalar_t>(),
            scales.data_ptr<float>(),
            d,
            static_cast<int>(topk),
            static_cast<int>(fp8type),
            nlt_ptr,
            eids_ptr,
            grid,
            num_local_tokens_tensor.has_value() && (!(num_tokens < 8192) || expect_m != -1),
            stream);
    });
}

void fuse_silu_mul_quant_ep(torch::Tensor& out,          // [E, T, d] int8
                            torch::Tensor& input,        // [E, T, 2 * d]
                            torch::Tensor& scales,       // [E, T, 1] fp32
                            std::optional<torch::Tensor> tokens_per_expert, // int32[E]
                            std::optional<torch::Tensor> num_local_tokens_tensor, // unused, parity
                            int64_t topk,                                                // unused
                            int64_t expect_m)                                            // unused
{
    TORCH_CHECK(input.dim() == 3, "input must be 3-dimensional [E, T, 2 * D]");
    TORCH_CHECK(input.is_contiguous(), "input must be contiguous");
    TORCH_CHECK(out.is_contiguous(), "out must be contiguous");
    TORCH_CHECK(out.scalar_type() == at::ScalarType::Char, "out must be int8");
    if(tokens_per_expert.has_value())
    {
        TORCH_CHECK(tokens_per_expert->scalar_type() == at::ScalarType::Int,
                    "tokens_per_expert must be int32");
        TORCH_CHECK(tokens_per_expert->is_contiguous(), "tokens_per_expert must be contiguous");
    }

    const int32_t E          = input.size(0);
    const int32_t T          = input.size(1);
    const int32_t d          = input.size(2) / 2;
    const int64_t num_tokens = static_cast<int64_t>(E) * T;
    TORCH_CHECK(input.size(2) % 2 == 0, "input's last dimension must be even");
    TORCH_CHECK(out.size(0) == E && out.size(1) == T && out.size(2) == d,
                "out must be [E, T, d]");
    TORCH_CHECK(scales.is_contiguous(), "scales must be contiguous");
    TORCH_CHECK(scales.size(0) == E && scales.size(1) == T && scales.size(2) == 1,
                "scales must be [E, T, 1]");
    if(tokens_per_expert.has_value())
        TORCH_CHECK(tokens_per_expert->numel() >= E, "tokens_per_expert must cover E experts");
    if(num_tokens == 0)
        return;

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(input));
    const hipStream_t stream = at::hip::getCurrentHIPStream();

    const int32_t* tpe_ptr =
        tokens_per_expert.has_value() ? tokens_per_expert->data_ptr<int32_t>() : nullptr;

    // token-major flat grid: one token per block, matching the 2D path
    const dim3 grid(static_cast<uint32_t>(num_tokens));
    AITER_DISPATCH_FUSED_ACT_TYPES(input.scalar_type(), "fuse_silu_mul_quant_ep", [&] {
        const auto aln = vec_align<scalar_t>(input.data_ptr<scalar_t>(), out.data_ptr());
        if(d <= 512 && d % 2 == 0 && aln.a2)
            act_mul_quant_ep_kernel<scalar_t, 2, 256, false>
                <<<grid, 256, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr<int8_t>()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, 0, T,
                                           tpe_ptr);
        else if(d <= 1024 && d % 8 == 0 && aln.a8)
            act_mul_quant_ep_kernel<scalar_t, 8, 128, false>
                <<<grid, 128, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr<int8_t>()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, 0, T,
                                           tpe_ptr);
        else if(d <= 2048 && d % 16 == 0 && num_tokens >= 512 && aln.a16)
            act_mul_quant_ep_kernel<scalar_t, 16, 128, false>
                <<<grid, 128, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr<int8_t>()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, 0, T,
                                           tpe_ptr);
        else if(d <= 2048 && d % 8 == 0 && aln.a8)
            act_mul_quant_ep_kernel<scalar_t, 8, 256, false>
                <<<grid, 256, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr<int8_t>()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, 0, T,
                                           tpe_ptr);
        else if(d <= 4096 && d % 16 == 0 && num_tokens >= 512 && aln.a16)
            act_mul_quant_ep_kernel<scalar_t, 16, 256, false>
                <<<grid, 256, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr<int8_t>()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, 0, T,
                                           tpe_ptr);
        else if(d <= 4096 && d % 8 == 0 && aln.a8)
            act_mul_quant_ep_kernel<scalar_t, 8, 512, false>
                <<<grid, 512, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr<int8_t>()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, 0, T,
                                           tpe_ptr);
        else if(d <= 8192 && d % 16 == 0 && num_tokens >= 512 && aln.a16)
            act_mul_quant_ep_kernel<scalar_t, 16, 512, false>
                <<<grid, 512, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr<int8_t>()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, 0, T,
                                           tpe_ptr);
        else if(d <= 8192 && d % 8 == 0 && aln.a8)
            act_mul_quant_ep_kernel<scalar_t, 8, 1024, false>
                <<<grid, 1024, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr<int8_t>()),
                                            input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, 0, T,
                                            tpe_ptr);
        else if(d <= 16384 && d % 16 == 0 && aln.a16)
            act_mul_quant_ep_kernel<scalar_t, 16, 1024, false>
                <<<grid, 1024, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr<int8_t>()),
                                            input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, 0, T,
                                            tpe_ptr);
        else if(d <= 32768 && d % 32 == 0 && aln.a32)
            act_mul_quant_ep_kernel<scalar_t, 32, 1024, false>
                <<<grid, 1024, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr<int8_t>()),
                                            input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, 0, T,
                                            tpe_ptr);
        else
            act_mul_quant_ep_kernel_generic<scalar_t, 1024, false>
                <<<grid, 1024, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr<int8_t>()),
                                            input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, 0, T,
                                            tpe_ptr);
    });
}

void fuse_silu_mul_fp8_quant_ep(torch::Tensor& out,      // [E, T, d] fp8
                                torch::Tensor& input,    // [E, T, 2 * d]
                                torch::Tensor& scales,   // [E, T, 1] fp32
                                int64_t fp8type,         // 0 = e4m3, 1 = e5m2
                                std::optional<torch::Tensor> tokens_per_expert,
                                std::optional<torch::Tensor> num_local_tokens_tensor, // unused
                                int64_t topk,                                         // unused
                                int64_t expect_m)                                     // unused
{
    TORCH_CHECK(input.dim() == 3, "input must be 3-dimensional [E, T, 2 * D]");
    TORCH_CHECK(input.is_contiguous(), "input must be contiguous");
    TORCH_CHECK(out.is_contiguous(), "out must be contiguous");
    TORCH_CHECK(fp8type == 0 || fp8type == 1, "fp8type must be 0 (e4m3) or 1 (e5m2)");
    if(tokens_per_expert.has_value())
    {
        TORCH_CHECK(tokens_per_expert->scalar_type() == at::ScalarType::Int,
                    "tokens_per_expert must be int32");
        TORCH_CHECK(tokens_per_expert->is_contiguous(), "tokens_per_expert must be contiguous");
    }

    const int32_t E          = input.size(0);
    const int32_t T          = input.size(1);
    const int32_t d          = input.size(2) / 2;
    const int64_t num_tokens = static_cast<int64_t>(E) * T;
    TORCH_CHECK(input.size(2) % 2 == 0, "input's last dimension must be even");
    TORCH_CHECK(out.size(0) == E && out.size(1) == T && out.size(2) == d,
                "out must be [E, T, d]");
    TORCH_CHECK(scales.is_contiguous(), "scales must be contiguous");
    TORCH_CHECK(scales.size(0) == E && scales.size(1) == T && scales.size(2) == 1,
                "scales must be [E, T, 1]");
    if(tokens_per_expert.has_value())
        TORCH_CHECK(tokens_per_expert->numel() >= E, "tokens_per_expert must cover E experts");
    if(num_tokens == 0)
        return;

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(input));
    const hipStream_t stream = at::hip::getCurrentHIPStream();

    const int32_t* tpe_ptr =
        tokens_per_expert.has_value() ? tokens_per_expert->data_ptr<int32_t>() : nullptr;

    // token-major flat grid: one token per block, matching the 2D path
    const dim3 grid(static_cast<uint32_t>(num_tokens));
    AITER_DISPATCH_FUSED_ACT_TYPES(input.scalar_type(), "fuse_silu_mul_fp8_quant_ep", [&] {
        const auto aln = vec_align<scalar_t>(input.data_ptr<scalar_t>(), out.data_ptr());
        if(d <= 512 && d % 4 == 0 && aln.a4)
            act_mul_quant_ep_kernel<scalar_t, 4, 128, true>
                <<<grid, 128, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, static_cast<int>(fp8type), T,
                                           tpe_ptr);
        else if(d <= 1024 && d % 8 == 0 && aln.a8)
            act_mul_quant_ep_kernel<scalar_t, 8, 128, true>
                <<<grid, 128, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, static_cast<int>(fp8type), T,
                                           tpe_ptr);
        else if(d <= 2048 && d % 16 == 0 && num_tokens >= 512 && aln.a16)
            act_mul_quant_ep_kernel<scalar_t, 16, 128, true>
                <<<grid, 128, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, static_cast<int>(fp8type), T,
                                           tpe_ptr);
        else if(d <= 2048 && d % 8 == 0 && aln.a8)
            act_mul_quant_ep_kernel<scalar_t, 8, 256, true>
                <<<grid, 256, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, static_cast<int>(fp8type), T,
                                           tpe_ptr);
        else if(d <= 4096 && d % 16 == 0 && num_tokens >= 512 && aln.a16)
            act_mul_quant_ep_kernel<scalar_t, 16, 256, true>
                <<<grid, 256, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, static_cast<int>(fp8type), T,
                                           tpe_ptr);
        else if(d <= 4096 && d % 8 == 0 && aln.a8)
            act_mul_quant_ep_kernel<scalar_t, 8, 512, true>
                <<<grid, 512, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, static_cast<int>(fp8type), T,
                                           tpe_ptr);
        else if(d <= 8192 && d % 16 == 0 && num_tokens >= 512 && aln.a16)
            act_mul_quant_ep_kernel<scalar_t, 16, 512, true>
                <<<grid, 512, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr()),
                                           input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, static_cast<int>(fp8type), T,
                                           tpe_ptr);
        else if(d <= 8192 && d % 8 == 0 && aln.a8)
            act_mul_quant_ep_kernel<scalar_t, 8, 1024, true>
                <<<grid, 1024, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr()),
                                            input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, static_cast<int>(fp8type), T,
                                            tpe_ptr);
        else if(d <= 16384 && d % 16 == 0 && aln.a16)
            act_mul_quant_ep_kernel<scalar_t, 16, 1024, true>
                <<<grid, 1024, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr()),
                                            input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, static_cast<int>(fp8type), T,
                                            tpe_ptr);
        else if(d <= 32768 && d % 32 == 0 && aln.a32)
            act_mul_quant_ep_kernel<scalar_t, 32, 1024, true>
                <<<grid, 1024, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr()),
                                            input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, static_cast<int>(fp8type), T,
                                            tpe_ptr);
        else
            act_mul_quant_ep_kernel_generic<scalar_t, 1024, true>
                <<<grid, 1024, 0, stream>>>(num_tokens, reinterpret_cast<uint8_t*>(out.data_ptr()),
                                            input.data_ptr<scalar_t>(), scales.data_ptr<float>(), d, static_cast<int>(fp8type), T,
                                            tpe_ptr);
    });
}

void fuse_silu_and_mul_ep(torch::Tensor& out,     // [E, T, d], same dtype as input
                          torch::Tensor& input,   // [E, T, 2 * d]
                          const torch::Tensor& mask_m, // int32[E], valid tokens per expert
                          int64_t expect_m)
{
    TORCH_CHECK(input.is_cuda() && out.is_cuda() && mask_m.is_cuda(),
                "input, out and mask_m must be CUDA tensors");
    TORCH_CHECK(input.is_contiguous() && out.is_contiguous() && mask_m.is_contiguous(),
                "input, out and mask_m must be contiguous");
    TORCH_CHECK(input.dim() == 3, "input must be shaped [E, T, 2 * D]");
    TORCH_CHECK(out.dim() == 3, "out must be shaped [E, T, D]");
    TORCH_CHECK(input.size(-1) % 2 == 0, "input's last dimension must be even");
    TORCH_CHECK(input.scalar_type() == out.scalar_type(), "input and out must have the same dtype");

    const int64_t num_experts      = input.size(0);
    const int64_t tokens_per_expert = input.size(1);
    const int64_t d                = input.size(-1) / 2;
    TORCH_CHECK(out.size(0) == num_experts && out.size(1) == tokens_per_expert && out.size(2) == d,
                "out must be shaped [E, T, D]");
    TORCH_CHECK(mask_m.dim() == 1 && mask_m.numel() == num_experts,
                "mask_m must be shaped [expert_nums]");
    TORCH_CHECK(mask_m.scalar_type() == at::ScalarType::Int, "mask_m must have torch.int32 dtype");
    if(num_experts == 0 || tokens_per_expert == 0 || d == 0)
        return;

    const int64_t expected_blocks =
        expect_m > 0 ? expect_m : tokens_per_expert;
    const int grid_y = static_cast<int>(std::max<int64_t>(1, std::min(tokens_per_expert, expected_blocks)));
    const dim3 grid(static_cast<uint32_t>(num_experts), static_cast<uint32_t>(grid_y));

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(input));
    const hipStream_t stream = at::hip::getCurrentHIPStream();

    const int32_t* mask_ptr = mask_m.data_ptr<int32_t>();
    AITER_DISPATCH_FUSED_ACT_TYPES(input.scalar_type(), "fuse_silu_and_mul_ep", [&] {
        if(d % 8 == 0 && d <= 8192)
        {
            int block_size = 1024;
            if(d <= 1024)
                block_size = 128;
            else if(d <= 2048 && d % 8 == 0)
                block_size = 256;
            else if(d <= 4096 && d % 8 == 0)
                block_size = 512;
            silu_and_mul_ep_kernel<scalar_t, 8>
                <<<grid, block_size, 0, stream>>>(out.data_ptr<scalar_t>(), input.data_ptr<scalar_t>(),
                                                  mask_ptr, d, tokens_per_expert);
        }
        else if(d % 2 == 0 && d <= 512)
        {
            silu_and_mul_ep_kernel<scalar_t, 2>
                <<<grid, 256, 0, stream>>>(out.data_ptr<scalar_t>(), input.data_ptr<scalar_t>(),
                                           mask_ptr, d, tokens_per_expert);
        }
        else
        {
            const int block_size = static_cast<int>(std::min<int64_t>(d, 1024));
            silu_and_mul_ep_kernel<scalar_t, 1>
                <<<grid, block_size, 0, stream>>>(out.data_ptr<scalar_t>(), input.data_ptr<scalar_t>(),
                                                  mask_ptr, d, tokens_per_expert);
        }
    });
}

void relu2(torch::Tensor& out,   // [..., d], same dtype as input
           torch::Tensor& input) // [..., d]
{
    const int d              = input.size(-1);
    const int64_t num_tokens = input.numel() / d;
    if(num_tokens == 0)
        return;

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(input));
    const hipStream_t stream = at::hip::getCurrentHIPStream();
    const dim3 grid(num_tokens);

    AITER_DISPATCH_FUSED_ACT_TYPES(input.scalar_type(), "relu2", [&] {
        auto* out_ptr   = out.data_ptr<scalar_t>();
        auto* input_ptr = input.data_ptr<scalar_t>();
        if(d == 168 && num_tokens >= 8 && num_tokens % 8 == 0)
        {
            relu2_kernel_multirow<scalar_t, 8, 168, 21, 8>
                <<<dim3(num_tokens / 8), 21 * 8, 0, stream>>>(out_ptr, input_ptr);
            return;
        }
        if(d == 336 && num_tokens >= 8 && num_tokens % 8 == 0)
        {
            relu2_kernel_multirow<scalar_t, 8, 336, 42, 8>
                <<<dim3(num_tokens / 8), 42 * 8, 0, stream>>>(out_ptr, input_ptr);
            return;
        }
        if(d == 672 && num_tokens >= 4 && num_tokens % 4 == 0)
        {
            relu2_kernel_multirow<scalar_t, 8, 672, 84, 4>
                <<<dim3(num_tokens / 4), 84 * 4, 0, stream>>>(out_ptr, input_ptr);
            return;
        }
        if(d % 8 == 0 && d <= 4096)
        {
            if(d <= 1024)
                relu2_kernel_vec<scalar_t, 8><<<grid, 128, 0, stream>>>(out_ptr, input_ptr, d);
            else if(d <= 2048 && d % 8 == 0)
                relu2_kernel_vec<scalar_t, 8><<<grid, 256, 0, stream>>>(out_ptr, input_ptr, d);
            else
                relu2_kernel_vec<scalar_t, 8><<<grid, 512, 0, stream>>>(out_ptr, input_ptr, d);
        }
        else
        {
            const dim3 block(std::min(d, 1024));
            relu2_kernel<scalar_t><<<grid, block, 0, stream>>>(out_ptr, input_ptr, d);
        }
    });
}

} // namespace aiter
