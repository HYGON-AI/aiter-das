// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
// SPDX-License-Identifier: MIT
//
// Native forward with c10 conversions, int64 indexing, bounded scalar
// tails, address alignment, strict guards, current stream. Large-D streaming
// forward is implemented separately; no cross-CTA spin or autograd.
#include "softmax.h"
#include "dispatch_utils.h"
#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <hip/hip_runtime.h>
#include <cstdint>
#include <limits>

namespace aiter {
namespace {
constexpr int kWave = 64;

template <typename T, int N>
struct alignas(sizeof(T) * N) AlignedVector
{
    T val[N];
};

template <bool Max>
__device__ __forceinline__ float wave_reduce(float value)
{
    #pragma unroll
    for(int mask = kWave / 2; mask; mask /= 2)
    {
        const float other = __shfl_xor(value, mask, kWave);
        value = Max ? fmaxf(value, other) : value + other;
    }
    return value;
}

template <bool Max, int Block>
__device__ __forceinline__ float block_reduce(float value, float* shared)
{
    const int lane = threadIdx.x % kWave;
    const int wave = threadIdx.x / kWave;
    value = wave_reduce<Max>(value);
    if(lane == 0)
        shared[wave] = value;
    __syncthreads();
    value = threadIdx.x < Block / kWave ? shared[lane] : (Max ? -INFINITY : 0.0f);
    if(wave == 0)
        value = wave_reduce<Max>(value);
    // All readers must finish before shared[0] is overwritten.
    __syncthreads();
    if(threadIdx.x == 0)
        shared[0] = value;
    __syncthreads();
    return shared[0];
}

template <typename T, int Vec, int Block, int Items = 1>
__global__ void softmax_kernel(const T* __restrict__ input,
                              T* __restrict__ output, int64_t cols)
{
    const int64_t offset = static_cast<int64_t>(blockIdx.x) * cols;
    __shared__ float shared[Block / kWave];
    float values[Items][Vec];
    float local_max = -INFINITY;
    #pragma unroll
    for(int i = 0; i < Items; ++i)
    {
        const int64_t col = (static_cast<int64_t>(threadIdx.x) + i * Block) * Vec;
        AlignedVector<T, Vec> loaded;
        if(col < cols)
            loaded = *reinterpret_cast<const AlignedVector<T, Vec>*>(input + offset + col);
        #pragma unroll
        for(int k = 0; k < Vec; ++k)
        {
            values[i][k] = col + k < cols ? static_cast<float>(loaded.val[k]) : -INFINITY;
            local_max = fmaxf(local_max, values[i][k]);
        }
    }
    const float maximum = block_reduce<true, Block>(local_max, shared);
    // No thread may reuse shared until every thread has read the maximum.
    __syncthreads();
    float local_sum = 0.0f;
    #pragma unroll
    for(int i = 0; i < Items; ++i)
    {
        const int64_t col = (static_cast<int64_t>(threadIdx.x) + i * Block) * Vec;
        #pragma unroll
        for(int k = 0; k < Vec; ++k)
        {
            const float shifted = values[i][k] - maximum;
            // Native __expf flushes subnormal results. The platform expf also
            // cuts off part of the FP32 minimum-subnormal range. Halving the
            // argument keeps expf normal; the FP32 multiply rounds gradual
            // underflow with this module's FTZ-disabled mode.
            float exponential;
            if(shifted < -80.0f)
            {
                const float half_exp = expf(shifted * 0.5f);
                exponential = half_exp * half_exp;
            }
            else
                exponential = __expf(shifted);
            values[i][k] = col + k < cols ? exponential : 0.0f;
            local_sum += values[i][k];
        }
    }
    const float inverse_sum = 1.0f / block_reduce<false, Block>(local_sum, shared);
    #pragma unroll
    for(int i = 0; i < Items; ++i)
    {
        const int64_t col = (static_cast<int64_t>(threadIdx.x) + i * Block) * Vec;
        if(col < cols)
        {
            AlignedVector<T, Vec> result;
            #pragma unroll
            for(int k = 0; k < Vec; ++k)
                result.val[k] = static_cast<T>(values[i][k] * inverse_sum);
            *reinterpret_cast<AlignedVector<T, Vec>*>(output + offset + col) = result;
        }
    }
}

// Keep memory and register use bounded independently of D. Three input passes
// (max, exp sum, normalized output) trade rereads for no global workspace.
__device__ __forceinline__ float stable_exp(float shifted)
{
    if(shifted < -80.0f)
    {
        const float half_exp = expf(shifted * 0.5f);
        return half_exp * half_exp;
    }
    return __expf(shifted);
}

template <typename T, int Vec, int Block>
__global__ void softmax_streaming_kernel(const T* __restrict__ input,
                                        T* __restrict__ output, int64_t cols)
{
    const int64_t offset = static_cast<int64_t>(blockIdx.x) * cols;
    __shared__ float shared[Block / kWave];
    float maximum = -INFINITY;
    for(int64_t col = static_cast<int64_t>(threadIdx.x) * Vec;
        col < cols; col += Block * Vec)
    {
        const auto values = *reinterpret_cast<const AlignedVector<T, Vec>*>(input + offset + col);
        #pragma unroll
        for(int k = 0; k < Vec; ++k)
            maximum = fmaxf(maximum, static_cast<float>(values.val[k]));
    }
    maximum = block_reduce<true, Block>(maximum, shared);
    __syncthreads();
    float sum = 0.0f;
    for(int64_t col = static_cast<int64_t>(threadIdx.x) * Vec;
        col < cols; col += Block * Vec)
    {
        const auto values = *reinterpret_cast<const AlignedVector<T, Vec>*>(input + offset + col);
        #pragma unroll
        for(int k = 0; k < Vec; ++k)
            sum += stable_exp(static_cast<float>(values.val[k]) - maximum);
    }
    const float inverse_sum = 1.0f / block_reduce<false, Block>(sum, shared);
    for(int64_t col = static_cast<int64_t>(threadIdx.x) * Vec;
        col < cols; col += Block * Vec)
    {
        const auto values = *reinterpret_cast<const AlignedVector<T, Vec>*>(input + offset + col);
        AlignedVector<T, Vec> result;
        #pragma unroll
        for(int k = 0; k < Vec; ++k)
            result.val[k] = static_cast<T>(
                stable_exp(static_cast<float>(values.val[k]) - maximum) * inverse_sum);
        *reinterpret_cast<AlignedVector<T, Vec>*>(output + offset + col) = result;
    }
}

template <typename T>
void launch(const T* input, T* output, int64_t rows, int64_t cols, hipStream_t stream)
{
    if(cols > 16384)
    {
        const bool aligned = cols % 8 == 0 &&
            reinterpret_cast<uintptr_t>(input) % (8 * sizeof(T)) == 0 &&
            reinterpret_cast<uintptr_t>(output) % (8 * sizeof(T)) == 0;
        if(aligned)
            softmax_streaming_kernel<T, 8, 256><<<rows, 256, 0, stream>>>(input, output, cols);
        else
            softmax_streaming_kernel<T, 1, 256><<<rows, 256, 0, stream>>>(input, output, cols);
        return;
    }
    // D8192 low-precision rows: four waves process two 16-element vectors
    // per thread, avoiding the original sixteen-wave CTA. Retain the scalar
    // and narrower-vector paths when the actual addresses are not aligned.
    if(cols == 8192 && sizeof(T) == 2 &&
       reinterpret_cast<uintptr_t>(input) % (16 * sizeof(T)) == 0 &&
       reinterpret_cast<uintptr_t>(output) % (16 * sizeof(T)) == 0)
    {
        softmax_kernel<T, 16, 256, 2><<<rows, 256, 0, stream>>>(input, output, cols);
        return;
    }
    const int vec = cols <= 8192 ? 8 : 16;
    const size_t alignment = vec * sizeof(T);
    const bool aligned = cols % vec == 0 &&
        reinterpret_cast<uintptr_t>(input) % alignment == 0 &&
        reinterpret_cast<uintptr_t>(output) % alignment == 0;
    const dim3 grid(static_cast<unsigned int>(rows));
    if(cols <= 128)
        softmax_kernel<T, 1, 128><<<grid, 128, 0, stream>>>(input, output, cols);
    else if(aligned)
    {
        if(cols <= 1024)
            softmax_kernel<T, 8, 128><<<grid, 128, 0, stream>>>(input, output, cols);
        else if(cols <= 2048)
            softmax_kernel<T, 8, 256><<<grid, 256, 0, stream>>>(input, output, cols);
        else if(cols <= 4096)
            softmax_kernel<T, 8, 512><<<grid, 512, 0, stream>>>(input, output, cols);
        else if(cols <= 8192)
            softmax_kernel<T, 8, 1024><<<grid, 1024, 0, stream>>>(input, output, cols);
        else
            softmax_kernel<T, 16, 1024><<<grid, 1024, 0, stream>>>(input, output, cols);
    }
    else
    {
        if(cols <= 1024)
            softmax_kernel<T, 1, 256, 4><<<grid, 256, 0, stream>>>(input, output, cols);
        else if(cols <= 2048)
            softmax_kernel<T, 1, 256, 8><<<grid, 256, 0, stream>>>(input, output, cols);
        else if(cols <= 4096)
            softmax_kernel<T, 1, 256, 16><<<grid, 256, 0, stream>>>(input, output, cols);
        else if(cols <= 8192)
            softmax_kernel<T, 1, 256, 32><<<grid, 256, 0, stream>>>(input, output, cols);
        else
            softmax_kernel<T, 1, 256, 64><<<grid, 256, 0, stream>>>(input, output, cols);
    }
}
} // namespace

void softmax_out(torch::Tensor& out, const torch::Tensor& input, int64_t dim)
{
    TORCH_CHECK(input.is_cuda() && out.is_cuda(), "softmax requires GPU tensors");
    TORCH_CHECK(input.dim() == 2 && (dim == -1 || dim == 1),
                "softmax requires a 2D input and dim=-1 or 1");
    const int64_t rows = input.size(0), cols = input.size(1);
    TORCH_CHECK(cols >= 1 && cols <= 524288, "softmax requires 1 <= D <= 524288");
    TORCH_CHECK(input.is_contiguous() && out.is_contiguous(),
                "softmax requires contiguous input and out");
    TORCH_CHECK(out.sizes() == input.sizes() && out.scalar_type() == input.scalar_type() &&
                    out.device() == input.device(),
                "softmax out must match input shape, dtype and device");
    TORCH_CHECK(input.scalar_type() == at::kHalf || input.scalar_type() == at::kBFloat16 ||
                    input.scalar_type() == at::kFloat, "softmax supports FP16, BF16 and FP32");
    TORCH_CHECK(!at::GradMode::is_enabled() || (!input.requires_grad() && !out.requires_grad()),
                "softmax is forward-only; use no_grad or inference_mode");
    if(rows == 0)
        return;
    const auto in_addr = reinterpret_cast<uintptr_t>(input.data_ptr());
    const auto out_addr = reinterpret_cast<uintptr_t>(out.data_ptr());
    const auto bytes = static_cast<size_t>(input.numel()) * input.element_size();
    TORCH_CHECK(in_addr < out_addr ? out_addr - in_addr >= bytes : in_addr - out_addr >= bytes,
                "softmax input and out must not overlap");
    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(input));
    hipDeviceProp_t props;
    TORCH_CHECK(hipGetDeviceProperties(&props, input.get_device()) == hipSuccess,
                "softmax cannot query device properties");
    TORCH_CHECK(rows <= props.maxGridSize[0], "softmax B exceeds the device grid limit");
    const hipStream_t stream = at::hip::getCurrentHIPStream();
    VLLM_DISPATCH_FLOATING_TYPES(input.scalar_type(), "softmax", [&] {
        launch(input.data_ptr<scalar_t>(), out.data_ptr<scalar_t>(), rows, cols, stream);
    });
    TORCH_CHECK(hipGetLastError() == hipSuccess, "softmax kernel launch failed");
}
} // namespace aiter
