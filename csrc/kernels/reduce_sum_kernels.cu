// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
// SPDX-License-Identifier: MIT
//
// Reduce-sum along the last dimension.
//
// Two arch paths (host-dispatched):
//   gfx936/gfx938 — W table tuned on real nmz; buffer_load + SLC
//   gfx946        — same 1-wave=1-row skeleton; 256B-line aware defaults;
//                   W table is provisional (retune on sb / real 946)
//
// Shared design:
//   - 1 wave = 1 row; W waves/block
//   - global -> VGPR via buffer_load_dwordx4
//   - fp32 accumulate; no LDS

#include <algorithm>
#include <cstdint>
#include <cstring>
#include <type_traits>

#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <hip/hip_fp16.h>
#include <torch/all.h>

#include "dispatch_utils.h"
#include "reduce_sum.h"

namespace aiter {
namespace {

constexpr int kWaveSize         = 64;
constexpr int kMaxWavesPerBlock = 16;
constexpr int kLoadBytes        = 16; // dwordx4

enum class ReduceSumArch
{
    Gfx938, // gfx936 / gfx938 family (64B cacheline, LDS 64KB)
    Gfx946, // shaobo (256B cacheline, LDS 128KB)
};

using i32x4 = int __attribute__((ext_vector_type(4)));
using u32x4 = unsigned int __attribute__((ext_vector_type(4)));

union BufferResource
{
    __device__ __forceinline__ BufferResource(const void* buffer_address, uint32_t buffer_size)
        : address(const_cast<void*>(buffer_address))
        , range(buffer_size)
        , config(0x00020000U)
    {
    }

    i32x4 descriptor;
    struct
    {
        void* address;
        uint32_t range;
        uint32_t config;
    };
};

__device__ i32x4 llvm_buffer_load_dwordx4(i32x4 srsrc,
                                          int32_t voffset,
                                          int32_t soffset,
                                          int32_t aux) __asm("llvm.amdgcn.raw.buffer.load.v4i32");

__device__ __forceinline__ u32x4
buffer_load_dwordx4_vgpr(i32x4 srsrc, int32_t voffset, int32_t aux = 0)
{
    return __builtin_bit_cast(u32x4,
                              llvm_buffer_load_dwordx4(srsrc, voffset, /*soffset=*/0, aux));
}

// gfx938: SLC helped on real nmz. gfx946: start with aux=0 until retuned.
constexpr int32_t kAuxSlcGfx938 = 2;
constexpr int32_t kAuxSlcGfx946 = 0;

__device__ __forceinline__ float wave_reduce_sum(float val)
{
#pragma unroll
    for(int offset = kWaveSize / 2; offset > 0; offset >>= 1)
    {
        val += __shfl_xor(val, offset);
    }
    return val;
}

__device__ __forceinline__ float u16_bits_to_float_as_bf16(uint16_t bits)
{
    return __builtin_bit_cast(float, static_cast<uint32_t>(bits) << 16);
}

__device__ __forceinline__ float u16_bits_to_float_as_fp16(uint16_t bits)
{
    return __half2float(__builtin_bit_cast(__half, bits));
}

template <typename scalar_t>
__device__ __forceinline__ float unpack_u32x4_sum(u32x4 raw)
{
    float acc = 0.f;
    if constexpr(std::is_same_v<scalar_t, float>)
    {
        const float* f = reinterpret_cast<const float*>(&raw);
#pragma unroll
        for(int i = 0; i < 4; ++i)
        {
            acc += f[i];
        }
    }
    else if constexpr(std::is_same_v<scalar_t, c10::Half>)
    {
#pragma unroll
        for(int i = 0; i < 4; ++i)
        {
            const uint32_t w = raw[i];
            acc += u16_bits_to_float_as_fp16(static_cast<uint16_t>(w & 0xffffu));
            acc += u16_bits_to_float_as_fp16(static_cast<uint16_t>(w >> 16));
        }
    }
    else
    {
#pragma unroll
        for(int i = 0; i < 4; ++i)
        {
            const uint32_t w = raw[i];
            acc += u16_bits_to_float_as_bf16(static_cast<uint16_t>(w & 0xffffu));
            acc += u16_bits_to_float_as_bf16(static_cast<uint16_t>(w >> 16));
        }
    }
    return acc;
}

template <typename scalar_t>
__device__ __forceinline__ float scalar_load_sum(const scalar_t* ptr)
{
    return static_cast<float>(*ptr);
}

// ---------------------------------------------------------------------------
// gfx938 path (nmz-tuned)
// ---------------------------------------------------------------------------

template <typename scalar_t>
__global__ void reduce_sum_kernel_buf_gfx938(const scalar_t* __restrict__ input,
                                             scalar_t* __restrict__ out,
                                             int64_t batch,
                                             int64_t dim,
                                             int waves_per_block)
{
    const int lane    = threadIdx.x & (kWaveSize - 1);
    const int wave_id = threadIdx.x >> 6;
    const int64_t row =
        static_cast<int64_t>(blockIdx.x) * waves_per_block + wave_id;
    if(row >= batch)
    {
        return;
    }

    const scalar_t* row_ptr = input + row * dim;
    const uint32_t row_bytes =
        static_cast<uint32_t>(dim * static_cast<int64_t>(sizeof(scalar_t)));
    BufferResource rsrc(row_ptr, row_bytes);

    constexpr int kElemsPerLoad = kLoadBytes / static_cast<int>(sizeof(scalar_t));
    const int64_t n_vec         = dim / kElemsPerLoad;

    float acc = 0.f;
    for(int64_t idx = lane; idx < n_vec; idx += kWaveSize)
    {
        u32x4 raw = buffer_load_dwordx4_vgpr(
            rsrc.descriptor, static_cast<int32_t>(idx * kLoadBytes), kAuxSlcGfx938);
        acc += unpack_u32x4_sum<scalar_t>(raw);
    }

    for(int64_t i = n_vec * kElemsPerLoad + lane; i < dim; i += kWaveSize)
    {
        acc += scalar_load_sum(row_ptr + i);
    }

    acc = wave_reduce_sum(acc);
    if(lane == 0)
    {
        out[row] = static_cast<scalar_t>(acc);
    }
}

template <typename scalar_t>
__global__ void reduce_sum_kernel_scalar_gfx938(const scalar_t* __restrict__ input,
                                                scalar_t* __restrict__ out,
                                                int64_t batch,
                                                int64_t dim,
                                                int waves_per_block)
{
    const int lane    = threadIdx.x & (kWaveSize - 1);
    const int wave_id = threadIdx.x >> 6;
    const int64_t row =
        static_cast<int64_t>(blockIdx.x) * waves_per_block + wave_id;
    if(row >= batch)
    {
        return;
    }

    const scalar_t* row_ptr = input + row * dim;
    float acc               = 0.f;
    for(int64_t i = lane; i < dim; i += kWaveSize)
    {
        acc += scalar_load_sum(row_ptr + i);
    }
    acc = wave_reduce_sum(acc);
    if(lane == 0)
    {
        out[row] = static_cast<scalar_t>(acc);
    }
}

// Tuned on real gfx938 / nmz.
inline int pick_waves_per_block_gfx938(int64_t batch, int64_t dim, int override_w)
{
    if(override_w > 0)
    {
        TORCH_CHECK(override_w <= kMaxWavesPerBlock,
                    "waves_per_block must be <= ",
                    kMaxWavesPerBlock);
        return override_w;
    }

    int w;
    if(dim <= 1024)
    {
        w = 4;
    }
    else if(dim <= 2048)
    {
        w = (batch >= 131072) ? 8 : 2;
    }
    else
    {
        w = 1;
    }

    if(static_cast<int64_t>(w) > batch)
    {
        w = static_cast<int>(batch);
    }
    return std::max(w, 1);
}

// ---------------------------------------------------------------------------
// gfx946 path (shaobo) — provisional W; retune offline on PerfModel / real HW
//
// 256B cacheline: dwordx4 keeps working (16 lanes × 16B = 1 line). Keep the
// same 1-wave=1-row mapping; only aux / default W differ until tuned.
// ---------------------------------------------------------------------------

template <typename scalar_t>
__global__ void reduce_sum_kernel_buf_gfx946(const scalar_t* __restrict__ input,
                                             scalar_t* __restrict__ out,
                                             int64_t batch,
                                             int64_t dim,
                                             int waves_per_block)
{
    const int lane    = threadIdx.x & (kWaveSize - 1);
    const int wave_id = threadIdx.x >> 6;
    const int64_t row =
        static_cast<int64_t>(blockIdx.x) * waves_per_block + wave_id;
    if(row >= batch)
    {
        return;
    }

    const scalar_t* row_ptr = input + row * dim;
    const uint32_t row_bytes =
        static_cast<uint32_t>(dim * static_cast<int64_t>(sizeof(scalar_t)));
    BufferResource rsrc(row_ptr, row_bytes);

    constexpr int kElemsPerLoad = kLoadBytes / static_cast<int>(sizeof(scalar_t));
    const int64_t n_vec         = dim / kElemsPerLoad;

    float acc = 0.f;
    // Stride waves in units that fill 256B lines when possible: each step still
    // uses dwordx4; consecutive lanes cover 16B*64 = 1024B = 4 lines / wave.
    for(int64_t idx = lane; idx < n_vec; idx += kWaveSize)
    {
        u32x4 raw = buffer_load_dwordx4_vgpr(
            rsrc.descriptor, static_cast<int32_t>(idx * kLoadBytes), kAuxSlcGfx946);
        acc += unpack_u32x4_sum<scalar_t>(raw);
    }

    for(int64_t i = n_vec * kElemsPerLoad + lane; i < dim; i += kWaveSize)
    {
        acc += scalar_load_sum(row_ptr + i);
    }

    acc = wave_reduce_sum(acc);
    if(lane == 0)
    {
        out[row] = static_cast<scalar_t>(acc);
    }
}

template <typename scalar_t>
__global__ void reduce_sum_kernel_scalar_gfx946(const scalar_t* __restrict__ input,
                                                scalar_t* __restrict__ out,
                                                int64_t batch,
                                                int64_t dim,
                                                int waves_per_block)
{
    const int lane    = threadIdx.x & (kWaveSize - 1);
    const int wave_id = threadIdx.x >> 6;
    const int64_t row =
        static_cast<int64_t>(blockIdx.x) * waves_per_block + wave_id;
    if(row >= batch)
    {
        return;
    }

    const scalar_t* row_ptr = input + row * dim;
    float acc               = 0.f;
    for(int64_t i = lane; i < dim; i += kWaveSize)
    {
        acc += scalar_load_sum(row_ptr + i);
    }
    acc = wave_reduce_sum(acc);
    if(lane == 0)
    {
        out[row] = static_cast<scalar_t>(acc);
    }
}

// Provisional defaults for gfx946 (NOT final). Safe for small-size verify;
// replace after overnight W sweep on PerfModel / real shaobo.
inline int pick_waves_per_block_gfx946(int64_t batch, int64_t dim, int override_w)
{
    if(override_w > 0)
    {
        TORCH_CHECK(override_w <= kMaxWavesPerBlock,
                    "waves_per_block must be <= ",
                    kMaxWavesPerBlock);
        return override_w;
    }

    // Start conservative: prefer enough blocks to fill CUs on moderate B.
    // TODO(tune-gfx946): replace with measured table.
    int w;
    if(dim <= 1024)
    {
        w = (batch >= 65536) ? 8 : 4;
    }
    else if(dim <= 2048)
    {
        w = (batch >= 131072) ? 8 : 4;
    }
    else
    {
        w = (batch >= 131072) ? 4 : 2;
    }

    if(static_cast<int64_t>(w) > batch)
    {
        w = static_cast<int>(batch);
    }
    return std::max(w, 1);
}

// ---------------------------------------------------------------------------
// Arch detect (PerfModel: prefer GPU_ARCHS / GPU_CHIP over gcnArchName)
// ---------------------------------------------------------------------------

inline ReduceSumArch detect_reduce_sum_arch()
{
    if(const char* env = std::getenv("GPU_ARCHS"))
    {
        // Runtime should use a single arch; still scan the string.
        if(std::strstr(env, "gfx946") != nullptr)
        {
            return ReduceSumArch::Gfx946;
        }
        if(std::strstr(env, "gfx938") != nullptr || std::strstr(env, "gfx936") != nullptr)
        {
            return ReduceSumArch::Gfx938;
        }
    }
    if(const char* chip = std::getenv("GPU_CHIP"))
    {
        if(std::strcmp(chip, "sb") == 0)
        {
            return ReduceSumArch::Gfx946;
        }
        if(std::strcmp(chip, "nmz") == 0 || std::strcmp(chip, "bw") == 0)
        {
            return ReduceSumArch::Gfx938;
        }
    }
    auto* props = at::cuda::getCurrentDeviceProperties();
    if(props && props->gcnArchName)
    {
        if(std::strstr(props->gcnArchName, "gfx946") != nullptr)
        {
            return ReduceSumArch::Gfx946;
        }
    }
    return ReduceSumArch::Gfx938;
}

inline int pick_waves_per_block(ReduceSumArch arch,
                                int64_t batch,
                                int64_t dim,
                                int override_w)
{
    if(arch == ReduceSumArch::Gfx946)
    {
        return pick_waves_per_block_gfx946(batch, dim, override_w);
    }
    return pick_waves_per_block_gfx938(batch, dim, override_w);
}

} // namespace

void reduce_sum(torch::Tensor& out, torch::Tensor& input, int64_t waves_per_block)
{
    TORCH_CHECK(input.is_cuda(), "reduce_sum: input must be CUDA/HIP tensor");
    TORCH_CHECK(out.is_cuda(), "reduce_sum: out must be CUDA/HIP tensor");
    TORCH_CHECK(input.scalar_type() == out.scalar_type(),
                "reduce_sum: input/out dtype mismatch");
    TORCH_CHECK(input.dim() >= 1, "reduce_sum: input must be at least 1-D");
    TORCH_CHECK(input.stride(-1) == 1, "reduce_sum: last dim must be contiguous");

    const int64_t dim   = input.size(-1);
    const int64_t batch = input.numel() / dim;

    TORCH_CHECK(out.numel() == batch, "reduce_sum: out numel must equal batch=", batch);
    TORCH_CHECK(dim > 0, "reduce_sum: dim must be > 0");

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(input));
    const hipStream_t stream = at::hip::getCurrentHIPStream();

    const ReduceSumArch arch = detect_reduce_sum_arch();
    const int W =
        pick_waves_per_block(arch, batch, dim, static_cast<int>(waves_per_block));

    const dim3 block(static_cast<unsigned>(W * kWaveSize));
    const dim3 grid(static_cast<unsigned>((batch + W - 1) / W));

    const bool use_buf =
        ((dim * static_cast<int64_t>(input.element_size())) % kLoadBytes == 0);

    VLLM_DISPATCH_FLOATING_TYPES(input.scalar_type(), "reduce_sum_kernel", [&] {
        if(arch == ReduceSumArch::Gfx946)
        {
            if(use_buf)
            {
                reduce_sum_kernel_buf_gfx946<scalar_t><<<grid, block, 0, stream>>>(
                    input.data_ptr<scalar_t>(),
                    out.data_ptr<scalar_t>(),
                    batch,
                    dim,
                    W);
            }
            else
            {
                reduce_sum_kernel_scalar_gfx946<scalar_t><<<grid, block, 0, stream>>>(
                    input.data_ptr<scalar_t>(),
                    out.data_ptr<scalar_t>(),
                    batch,
                    dim,
                    W);
            }
        }
        else
        {
            if(use_buf)
            {
                reduce_sum_kernel_buf_gfx938<scalar_t><<<grid, block, 0, stream>>>(
                    input.data_ptr<scalar_t>(),
                    out.data_ptr<scalar_t>(),
                    batch,
                    dim,
                    W);
            }
            else
            {
                reduce_sum_kernel_scalar_gfx938<scalar_t><<<grid, block, 0, stream>>>(
                    input.data_ptr<scalar_t>(),
                    out.data_ptr<scalar_t>(),
                    batch,
                    dim,
                    W);
            }
        }
    });
}

} // namespace aiter
