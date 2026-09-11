// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
//
// Kimi K3 AttnRes（gfx936/gfx946）。只保留生产路径上的六个 kernel，ID 从 0 重新编号。
//
// 当前 OpusK3AttnResKernel（Python：aiter.ops.opus.OpusK3AttnResKernel）
//   Auto            按形状自动选择（kernelId=None）
//   Fallback        通用回退。make_layout / make_gmem，覆盖未对齐、任意 hidden / blocks。
//   AlignedGeneral  对齐通用路径（原 19）。256/512 线程寄存器流水线；delta /
//                   block-write / output RMSNorm / num_blocks 编译期钉死。
//                   hidden=4096 再钉 HiddenSize、Triton 同款 decode 线程数
//                   （tokens<256 且 num_blocks>1 时 512，否则 256），以及
//                   decode 的 SourceTile=4（对应 Triton BLOCK_L=4，循环卷起）。
//   DecodeSplit     深 decode 切 hidden（原 37）。14 个 64 线程 workgroup 算 9x9 Gram。
//   Decode          decode（原 41）。512 线程、每轮 3 个 source，input_qk 留在寄存器。
//   Prefill         中等 token（原 14）。256 线程，SingleExp + 折叠 output RMSNorm。
//   LargeBatch      大 token（原 13）。同几何，仅折叠 output RMSNorm。
//
// 自动分派（Auto / kernelId=None）
//   主形状（hidden=7168、8 blocks、无 delta/block-write、output RMSNorm、16 字节对齐）：
//     tokens < 25            -> DecodeSplit
//     25 <= tokens < 96      -> Decode
//     96 <= tokens < 8192    -> Prefill
//     tokens >= 8192         -> LargeBatch
//   gfx936 其他 16 字节对齐形状 -> AlignedGeneral；其余 -> Fallback
//   gfx946                    -> Fallback（可显式选择已验证的 AlignedGeneral）
//
// 实验结论（否决项已从源码删除，结论留在这里）
//   * 热路径不要改回 opus_gemm 风格的 make_gmem。六个 16B 描述符跨 source 循环存活
//     会溢出约 96B private/scratch；改成对齐 BF16x8 直接向量访存后 private=0，decode
//     才超过 Triton。AttnRes 不是 GEMM，没有 make_tiled_mma。变慢的原因是描述符
//     spill，不是手算地址、不是 padding、也不是块不够大。
//   * Scratch 是寄存器不够时溢到 per-thread 私有内存，延迟接近全局访存。本课题量过
//     约 18 ns/B。decode 时间近似 17.9 us + 18 ns/B * scratch。
//   * 原 ID20（512 线程 x 2 source）寄存器余量为零。在它上面加宽 tile 并展开
//     （原 23--25）、软件流水并展开（原 28--33）、或再塞一个活值，全部 spill。
//     真正的问题是「加宽且展开」。卷起循环的原 ID41（现 ID3，3 source/轮）
//     private=0，并在 25--95 tokens 全程优于原 ID20。
//   * 原 ID28--36 用 static_for 展开 source 循环做软件流水，寄存器余量为零，全部否决。
//   * 原 ID37（现 ID2）看起来「两态」不是 kernel 抽签。历史 --graph 把 iterations 次
//     调用打进一张 graph，每次 at::empty 一块中转 buffer。生产是捕获一次再 replay。
//     测 decode 请用 --graph --graph-replay。生产口径 tokens=17 稳定约 1.20x Triton。
//   * gfx936 L2 = 8 MB。tokens=64 时激活源 X 约 8.06 MB，切 hidden 的第二遍读 X 会掉出
//     L2，所以 ID2 只吃 tokens<25；从 25 起交给 ID3。
//   * 已删除且确认不再使用：原 1--12、15--18、20--36、38--40、42（512x1 / 1024x1 /
//     192x1 / 256x2 / all-source 双遍 / 加宽展开 tile / 命名寄存器 / 软件流水 /
//     8x7168 LDS / 动态 general ID15 / split-7 / 512xn 的 LDS 与 BF16 qk 变体）。
//
#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>

#include "opus/opus.hpp"
#include "opus_k3_attn_res.h"
#include "opus_k3_attn_res_gfx946.cuh"

#include <cmath>
#include <cstdint>
#include <cstring>
#include <stdexcept>
#include <string>
#include <utility>

namespace {

constexpr int kThreads = 256;
constexpr int kWaveSize = 64;
constexpr int kWaves = kThreads / kWaveSize;
constexpr int kMaxBlocks = 8;
constexpr int kMaxHidden = 8192;
constexpr int kK3Hidden = 7168;
constexpr int kLargeTokenThreshold = 8192;
// tokens>=96 时主形状走 Prefill；低于此值 decode 受延迟限制。
constexpr int kDecodeTokenThreshold = 96;
// tokens<25 时 DecodeSplit 仍优于 Decode，且相对 Triton 大约 2% 以内。
constexpr int kSplitTokenThreshold = 25;

void require(bool condition, const std::string& message)
{
    if(!condition)
        throw std::runtime_error("opus_k3_attn_res: " + message);
}

enum class RuntimeHcuArch
{
    Unsupported,
    Gfx936,
    Gfx946,
};

RuntimeHcuArch runtime_hcu_arch(int device)
{
    thread_local int cached_device = -1;
    thread_local RuntimeHcuArch cached_arch = RuntimeHcuArch::Unsupported;
    if(cached_device != device)
    {
        hipDeviceProp_t prop{};
        cached_arch = RuntimeHcuArch::Unsupported;
        if(hipGetDeviceProperties(&prop, device) == hipSuccess)
        {
            if(std::strncmp(prop.gcnArchName, "gfx936", 6) == 0)
                cached_arch = RuntimeHcuArch::Gfx936;
            else if(std::strncmp(prop.gcnArchName, "gfx946", 6) == 0)
                cached_arch = RuntimeHcuArch::Gfx946;
        }
        cached_device = device;
    }
    return cached_arch;
}

template <typename T>
bool is_aligned(const T* ptr, std::uintptr_t alignment)
{
    return reinterpret_cast<std::uintptr_t>(ptr) % alignment == 0;
}

#if defined(__HIP_DEVICE_COMPILE__)

OPUS_D float wave_reduce_sum(float value)
{
    const int lane = static_cast<int>(opus::lane_id());
#pragma unroll
    for(int offset = kWaveSize / 2; offset > 0; offset >>= 1)
        value += opus::shfl(value, lane ^ offset, kWaveSize);
    return value;
}

// The last lane receives the full wave64 sum. DPP avoids the ds_bpermute and
// waitcnt chain emitted by the generic shuffle helper.
OPUS_D float wave_reduce_sum_dpp(float value)
{
    value += opus::mov_dpp(value, opus::number<0xb1>{});
    value += opus::mov_dpp(value, opus::number<0x4e>{});
    value += opus::mov_dpp(value, opus::number<0x124>{});
    value += opus::mov_dpp(value, opus::number<0x128>{});
    value += opus::mov_dpp(value, opus::number<0x142>{});
    value += opus::mov_dpp(value, opus::number<0x143>{});
    return value;
}

template <int Count, int Waves>
OPUS_D void block_reduce_pairs_dpp(float (&first)[Count],
                                   float (&second)[Count],
                                   float* wave_first,
                                   float* wave_second,
                                   float* block_first,
                                   float* block_second)
{
    const int tid = opus::thread_id_x();
    const int lane = static_cast<int>(opus::lane_id());
    const int wave = tid / kWaveSize;
    opus::static_for<Count>([&](auto i) {
        constexpr int I = decltype(i)::value;
        first[I] = wave_reduce_sum_dpp(first[I]);
        second[I] = wave_reduce_sum_dpp(second[I]);
        if(lane == kWaveSize - 1)
        {
            wave_first[I * Waves + wave] = first[I];
            wave_second[I * Waves + wave] = second[I];
        }
    });
    opus::sync_threads();

    if(wave == 0)
    {
        opus::static_for<Count>([&](auto i) {
            constexpr int I = decltype(i)::value;
            float group_first = lane < Waves ? wave_first[I * Waves + lane] : 0.0f;
            float group_second = lane < Waves ? wave_second[I * Waves + lane] : 0.0f;
            group_first = wave_reduce_sum_dpp(group_first);
            group_second = wave_reduce_sum_dpp(group_second);
            if(lane == kWaveSize - 1)
            {
                block_first[I] = group_first;
                block_second[I] = group_second;
            }
        });
    }
    opus::sync_threads();
}

template <int Waves>
OPUS_D __forceinline__ opus::vector_t<opus::fp32_t, 2>
block_reduce_pair_dpp_scalar(float first,
                             float second,
                             float* wave_first,
                             float* wave_second,
                             float* block_first,
                             float* block_second)
{
    const int tid = opus::thread_id_x();
    const int lane = static_cast<int>(opus::lane_id());
    const int wave = tid / kWaveSize;
    first = wave_reduce_sum_dpp(first);
    second = wave_reduce_sum_dpp(second);
    if(lane == kWaveSize - 1)
    {
        wave_first[wave] = first;
        wave_second[wave] = second;
    }
    opus::sync_threads();
    if(wave == 0)
    {
        float group_first = lane < Waves ? wave_first[lane] : 0.0f;
        float group_second = lane < Waves ? wave_second[lane] : 0.0f;
        group_first = wave_reduce_sum_dpp(group_first);
        group_second = wave_reduce_sum_dpp(group_second);
        if(lane == kWaveSize - 1)
        {
            *block_first = group_first;
            *block_second = group_second;
        }
    }
    opus::sync_threads();
    return {*block_first, *block_second};
}


OPUS_D __forceinline__ opus::vector_t<opus::fp32_t, 8>
bf16x8_to_fp32(opus::vector_t<opus::bf16_t, 8> raw)
{
    return {opus::bf16_to_fp32(raw[0]),
            opus::bf16_to_fp32(raw[1]),
            opus::bf16_to_fp32(raw[2]),
            opus::bf16_to_fp32(raw[3]),
            opus::bf16_to_fp32(raw[4]),
            opus::bf16_to_fp32(raw[5]),
            opus::bf16_to_fp32(raw[6]),
            opus::bf16_to_fp32(raw[7])};
}

OPUS_D __forceinline__ float horizontal_sum8(opus::vector_t<opus::fp32_t, 8> x)
{
    const float s01 = x[0] + x[1];
    const float s23 = x[2] + x[3];
    const float s45 = x[4] + x[5];
    const float s67 = x[6] + x[7];
    return (s01 + s23) + (s45 + s67);
}

OPUS_D __forceinline__ opus::vector_t<opus::bf16_t, 8>
fp32x8_to_bf16_rne(opus::vector_t<opus::fp32_t, 8> x)
{
#if defined(__gfx946__)
    return opus_k3_attn_res_gfx946::fp32x8_to_bf16_rne_asm(x);
#else
    return {opus::fp32_to_bf16(x[0], opus::number<0>{}),
            opus::fp32_to_bf16(x[1], opus::number<0>{}),
            opus::fp32_to_bf16(x[2], opus::number<0>{}),
            opus::fp32_to_bf16(x[3], opus::number<0>{}),
            opus::fp32_to_bf16(x[4], opus::number<0>{}),
            opus::fp32_to_bf16(x[5], opus::number<0>{}),
            opus::fp32_to_bf16(x[6], opus::number<0>{}),
            opus::fp32_to_bf16(x[7], opus::number<0>{})};
#endif
}

// The specialized K3 hot path has a fixed contiguous hidden dimension and a
// 16-byte alignment contract.  Keeping six make_gmem resource descriptors live
// across the runtime source loop makes AICC spill the descriptors to a 96-byte
// private segment.  Direct vector accesses preserve the same 128-bit
// transactions without that descriptor lifetime.
OPUS_D __forceinline__ opus::vector_t<opus::bf16_t, 8>
load_bf16x8_aligned(const opus::bf16_t* ptr, long long element_offset)
{
    using BVec = opus::vector_t<opus::bf16_t, 8>;
    return *reinterpret_cast<const BVec*>(ptr + element_offset);
}

OPUS_D __forceinline__ opus::vector_t<opus::bf16_t, 8>
load_bf16x8_buffer(__amdgpu_buffer_rsrc_t resource, int byte_offset)
{
    using BVec = opus::vector_t<opus::bf16_t, 8>;
    const auto raw = __builtin_hcu_raw_buffer_load_b128(resource, byte_offset, 0, 0);
    return *reinterpret_cast<const BVec*>(&raw);
}

OPUS_D __forceinline__ void
store_bf16x8_aligned(opus::bf16_t* ptr,
                     long long element_offset,
                     opus::vector_t<opus::bf16_t, 8> value)
{
    using BVec = opus::vector_t<opus::bf16_t, 8>;
    *reinterpret_cast<BVec*>(ptr + element_offset) = value;
}

OPUS_D __forceinline__ void
store_bf16x8_buffer(__amdgpu_buffer_rsrc_t resource,
                    int byte_offset,
                    opus::vector_t<opus::bf16_t, 8> value)
{
    __builtin_hcu_raw_buffer_store_b128(
        __builtin_bit_cast(opus::i32x4_t, value), resource, byte_offset, 0, 0);
}

OPUS_D __forceinline__ void load_k3_exact_source(
    __amdgpu_buffer_rsrc_t prefix_resource,
    __amdgpu_buffer_rsrc_t blocks_resource,
    long long prefix_row_offset,
    long long blocks_row_offset,
    long long stride_block_r,
    int source,
    int base0,
    int base1,
    int base2,
    int base3,
    opus::vector_t<opus::bf16_t, 8>& raw0,
    opus::vector_t<opus::bf16_t, 8>& raw1,
    opus::vector_t<opus::bf16_t, 8>& raw2,
    opus::vector_t<opus::bf16_t, 8>& raw3)
{
    if(source == kMaxBlocks)
    {
        raw0 = load_bf16x8_buffer(
            prefix_resource, static_cast<int>((prefix_row_offset + base0) * 2));
        raw1 = load_bf16x8_buffer(
            prefix_resource, static_cast<int>((prefix_row_offset + base1) * 2));
        raw2 = load_bf16x8_buffer(
            prefix_resource, static_cast<int>((prefix_row_offset + base2) * 2));
        if(base3 < kK3Hidden)
            raw3 = load_bf16x8_buffer(
                prefix_resource, static_cast<int>((prefix_row_offset + base3) * 2));
    }
    else
    {
        const long long source_offset =
            blocks_row_offset + static_cast<long long>(source) * stride_block_r;
        raw0 = load_bf16x8_buffer(
            blocks_resource, static_cast<int>((source_offset + base0) * 2));
        raw1 = load_bf16x8_buffer(
            blocks_resource, static_cast<int>((source_offset + base1) * 2));
        raw2 = load_bf16x8_buffer(
            blocks_resource, static_cast<int>((source_offset + base2) * 2));
        if(base3 < kK3Hidden)
            raw3 = load_bf16x8_buffer(
                blocks_resource, static_cast<int>((source_offset + base3) * 2));
    }
}

OPUS_D __forceinline__ opus::vector_t<opus::bf16_t, 8>
add_bf16x8_rne(opus::vector_t<opus::bf16_t, 8> lhs,
               opus::vector_t<opus::bf16_t, 8> rhs)
{
    return fp32x8_to_bf16_rne(bf16x8_to_fp32(lhs) + bf16x8_to_fp32(rhs));
}

OPUS_D void block_reduce_pair(float first,
                              float second,
                              float* wave_first,
                              float* wave_second,
                              float* block_first,
                              float* block_second)
{
    const int tid = opus::thread_id_x();
    const int lane = tid % kWaveSize;
    const int wave = tid / kWaveSize;
    first = wave_reduce_sum(first);
    second = wave_reduce_sum(second);
    if(lane == 0)
    {
        wave_first[wave] = first;
        wave_second[wave] = second;
    }
    opus::sync_threads();

    if(wave == 0)
    {
        float group_first = lane < kWaves ? wave_first[lane] : 0.0f;
        float group_second = lane < kWaves ? wave_second[lane] : 0.0f;
        group_first = wave_reduce_sum(group_first);
        group_second = wave_reduce_sum(group_second);
        if(lane == 0)
        {
            *block_first = group_first;
            *block_second = group_second;
        }
    }
    opus::sync_threads();
}

#endif

// Fallback：任意 hidden / 未对齐。语义拆成独立遍，覆盖面最大，热路径不用这条。
// 流程：
//   [1] 建 layout / gmem 描述符，按 stride 寻址（可未对齐）
//   [2] 更新 prefix（+delta，可选写入 block bank），BF16 往返后缓存
//   [3] 逐 source 扫 hidden：RMSNorm 打分，block reduce 得到 logit
//   [4] tid0 做稳定 softmax，概率写入 LDS
//   [5] 再扫 hidden：按概率加权混合
//   [6] 可选 output RMSNorm，写 output
template <int NumBlocks, int Vec>
__global__ void __launch_bounds__(kThreads, 1) opus_k3_attn_res_kernel(void* prefix_ptr,
                                        const void* delta_ptr,
                                        void* blocks_ptr,
                                        const void* norm_weight_ptr,
                                        const void* qk_weight_ptr,
                                        const void* output_norm_weight_ptr,
                                        void* output_ptr,
                                        long long stride_prefix_m,
                                        long long stride_delta_m,
                                        long long stride_block_m,
                                        long long stride_block_r,
                                        long long stride_output_m,
                                        int num_tokens,
                                        int block_capacity,
                                        int hidden_size,
                                        int block_write_idx,
                                        float eps,
                                        float output_norm_eps,
                                        bool has_delta,
                                        bool apply_output_norm)
{
#if defined(__HIP_DEVICE_COMPILE__) && (defined(__gfx936__) || defined(__gfx946__))
    static_assert(NumBlocks >= 0 && NumBlocks <= kMaxBlocks);
    static_assert(Vec == 1 || Vec == 4);
    constexpr int NumSources = NumBlocks + 1;
    constexpr int MaxIterations = (kMaxHidden + kThreads * Vec - 1) / (kThreads * Vec);
    using BVec = opus::vector_t<opus::bf16_t, Vec>;
    using FVec = opus::vector_t<opus::fp32_t, Vec>;

    __shared__ float wave_first[kWaves];
    __shared__ float wave_second[kWaves];
    __shared__ float block_first;
    __shared__ float block_second;
    __shared__ float logits[kMaxBlocks + 1];
    __shared__ float probabilities[kMaxBlocks + 1];

    const int tid = opus::thread_id_x();
    const int row = opus::block_id_x();
    if(row >= num_tokens)
        return;

    // [1] layout 把 (row, hidden) 映成元素偏移；gmem 描述符走 buffer load。
    auto prefix_layout = opus::make_layout(
        opus::make_tuple(num_tokens, hidden_size),
        opus::make_tuple(stride_prefix_m, 1));
    auto delta_layout = opus::make_layout(
        opus::make_tuple(num_tokens, hidden_size),
        opus::make_tuple(stride_delta_m, 1));
    auto blocks_layout = opus::make_layout(
        opus::make_tuple(num_tokens, block_capacity, hidden_size),
        opus::make_tuple(stride_block_m, stride_block_r, 1));
    auto output_layout = opus::make_layout(
        opus::make_tuple(num_tokens, hidden_size),
        opus::make_tuple(stride_output_m, 1));
    auto g_prefix = opus::make_gmem(reinterpret_cast<opus::bf16_t*>(prefix_ptr));
    auto g_delta = opus::make_gmem(reinterpret_cast<const opus::bf16_t*>(delta_ptr));
    auto g_blocks = opus::make_gmem(reinterpret_cast<opus::bf16_t*>(blocks_ptr));
    auto g_norm = opus::make_gmem(reinterpret_cast<const opus::bf16_t*>(norm_weight_ptr));
    auto g_qk = opus::make_gmem(reinterpret_cast<const opus::bf16_t*>(qk_weight_ptr));
    auto g_output_norm =
        opus::make_gmem(reinterpret_cast<const opus::bf16_t*>(output_norm_weight_ptr));
    auto g_output = opus::make_gmem(reinterpret_cast<opus::bf16_t*>(output_ptr));

    FVec prefix_cache[MaxIterations];

    // [2] 先改 prefix。BF16 往返是对外融合语义的一部分，后面打分必须用舍入后的值。
    int iteration = 0;
    for(int base = tid * Vec; base < hidden_size; base += kThreads * Vec, ++iteration)
    {
        const int logical_base = base;
        const int prefix_offset = prefix_layout(row, logical_base);
        BVec prefix_raw = g_prefix.template load<Vec>(prefix_offset);
        BVec updated_raw;
        if(has_delta)
        {
            const int delta_offset = delta_layout(row, logical_base);
            BVec delta_raw = g_delta.template load<Vec>(delta_offset);
#pragma unroll
            for(int j = 0; j < Vec; ++j)
            {
                const float updated = opus::bf16_to_fp32(prefix_raw[j]) +
                                      opus::bf16_to_fp32(delta_raw[j]);
                updated_raw[j] = opus::fp32_to_bf16(updated, opus::number<0>{});
                prefix_cache[iteration][j] = opus::bf16_to_fp32(updated_raw[j]);
            }
            g_prefix.template store<Vec>(updated_raw, prefix_offset);
        }
        else
        {
            updated_raw = prefix_raw;
#pragma unroll
            for(int j = 0; j < Vec; ++j)
                prefix_cache[iteration][j] = opus::bf16_to_fp32(prefix_raw[j]);
        }

        if(block_write_idx >= 0)
        {
            const int block_offset = blocks_layout(row, block_write_idx, logical_base);
            g_blocks.template store<Vec>(updated_raw, block_offset);
        }
    }

    // 最后一个 source 是更新后的 prefix；写过的 bank 槽也走缓存，避免读到旧值。
    auto load_source = [&](int source, int base, int cache_index) -> FVec {
        if(source == NumBlocks || source == block_write_idx)
            return prefix_cache[cache_index];
        const int block_offset = blocks_layout(row, source, base);
        BVec raw = g_blocks.template load<Vec>(block_offset);
        FVec values;
#pragma unroll
        for(int j = 0; j < Vec; ++j)
            values[j] = opus::bf16_to_fp32(raw[j]);
        return values;
    };

    if constexpr(NumBlocks == 0)
    {
        // 没有 bank source，混合就是 prefix 自身，概率恒为 1。
        if(tid == 0)
            probabilities[0] = 1.0f;
        opus::sync_threads();
    }
    else
    {
        // [3] 每个 source 单独过一遍 hidden：局部平方和与 qk 点积，再 workgroup 规约。
#pragma unroll
        for(int source = 0; source < NumSources; ++source)
        {
            float square_sum = 0.0f;
            float qk_sum = 0.0f;
            int cache_index = 0;
            for(int base = tid * Vec; base < hidden_size;
                base += kThreads * Vec, ++cache_index)
            {
                const int logical_base = base;
                const FVec values = load_source(source, logical_base, cache_index);
                const BVec norm_raw = g_norm.template load<Vec>(logical_base);
                const BVec qk_raw = g_qk.template load<Vec>(logical_base);
#pragma unroll
                for(int j = 0; j < Vec; ++j)
                {
                    const float value = values[j];
                    square_sum += value * value;
                    qk_sum += value * opus::bf16_to_fp32(norm_raw[j]) *
                              opus::bf16_to_fp32(qk_raw[j]);
                }
            }
            block_reduce_pair(square_sum,
                              qk_sum,
                              wave_first,
                              wave_second,
                              &block_first,
                              &block_second);
            if(tid == 0)
                logits[source] =
                    block_second * rsqrtf(block_first / hidden_size + eps);
        }

        // [4] 全 source 的 logit 齐了再 softmax，数值最稳，但要多一次同步。
        if(tid == 0)
        {
            float max_logit = -INFINITY;
#pragma unroll
            for(int source = 0; source < NumSources; ++source)
                max_logit = fmaxf(max_logit, logits[source]);
            float denominator = 0.0f;
#pragma unroll
            for(int source = 0; source < NumSources; ++source)
            {
                probabilities[source] = expf(logits[source] - max_logit);
                denominator += probabilities[source];
            }
#pragma unroll
            for(int source = 0; source < NumSources; ++source)
                probabilities[source] /= denominator;
        }
        opus::sync_threads();
    }

    // [5] 概率已知后，再读一遍各 source，做加权和；顺带攒 output RMSNorm 的平方和。
    FVec mixed_cache[MaxIterations];
    iteration = 0;
    float output_square_sum = 0.0f;
    for(int base = tid * Vec; base < hidden_size; base += kThreads * Vec, ++iteration)
    {
        const int logical_base = base;
        FVec mixed{};
#pragma unroll
        for(int source = 0; source < NumSources; ++source)
        {
            const FVec values = load_source(source, logical_base, iteration);
#pragma unroll
            for(int j = 0; j < Vec; ++j)
                mixed[j] += probabilities[source] * values[j];
        }
        mixed_cache[iteration] = mixed;
        if(apply_output_norm)
        {
#pragma unroll
            for(int j = 0; j < Vec; ++j)
                output_square_sum += mixed[j] * mixed[j];
        }
    }

    // [6] output RMSNorm 的 rsqrt 作用在已经 softmax 归一化后的 mixed 上。
    float output_inv = 1.0f;
    if(apply_output_norm)
    {
        block_reduce_pair(output_square_sum,
                          0.0f,
                          wave_first,
                          wave_second,
                          &block_first,
                          &block_second);
        output_inv = rsqrtf(block_first / hidden_size + output_norm_eps);
    }

    iteration = 0;
    for(int base = tid * Vec; base < hidden_size; base += kThreads * Vec, ++iteration)
    {
        const int logical_base = base;
        FVec mixed = mixed_cache[iteration];
        if(apply_output_norm)
        {
            const BVec weight_raw = g_output_norm.template load<Vec>(logical_base);
#pragma unroll
            for(int j = 0; j < Vec; ++j)
                mixed[j] *= output_inv * opus::bf16_to_fp32(weight_raw[j]);
        }
        BVec result;
#pragma unroll
        for(int j = 0; j < Vec; ++j)
            result[j] = opus::fp32_to_bf16(mixed[j], opus::number<0>{});
        g_output.template store<Vec>(result, output_layout(row, logical_base));
    }
#else
    (void)prefix_ptr;
    (void)delta_ptr;
    (void)blocks_ptr;
    (void)norm_weight_ptr;
    (void)qk_weight_ptr;
    (void)output_norm_weight_ptr;
    (void)output_ptr;
    (void)stride_prefix_m;
    (void)stride_delta_m;
    (void)stride_block_m;
    (void)stride_block_r;
    (void)stride_output_m;
    (void)num_tokens;
    (void)block_capacity;
    (void)hidden_size;
    (void)block_write_idx;
    (void)eps;
    (void)output_norm_eps;
    (void)has_delta;
    (void)apply_output_norm;
#endif
}


// Prefill / LargeBatch（原 14/13）：主形状 hidden=7168、256 线程、无 delta。
// 把 Fallback 的打分 / softmax / 混合融进一次 source 循环，四个 BF16x8 chunk 留在寄存器。
// 流程：
//   [1] 预乘 input_qk = norm * qk（对所有 source 不变）
//   [2] 逐 source：load → 局部平方和/点积 → DPP 规约 → 在线 softmax 累加 mixed
//   [3] 折叠 output RMSNorm（不先除 softmax 分母）并写回
// PrefetchNext / BufferStore 是实验开关，生产路径都是 false。
template <bool SingleExp,
          bool FoldOutputNorm,
          bool PrefetchNext = false,
          bool BufferStore = false>
__global__ void __launch_bounds__(256, 1)
opus_k3_attn_res_fast_256x1_register_kernel(
    const void* prefix_ptr,
    const void* blocks_ptr,
    const void* norm_weight_ptr,
    const void* qk_weight_ptr,
    const void* output_norm_weight_ptr,
    void* output_ptr,
    long long stride_prefix_m,
    long long stride_block_m,
    long long stride_block_r,
    long long stride_output_m,
    int num_tokens,
    float eps,
    float output_norm_eps)
{
#if defined(__HIP_DEVICE_COMPILE__) && (defined(__gfx936__) || defined(__gfx946__))
    constexpr int Threads = 256;
    constexpr int Vec = 8;
    constexpr int Waves = Threads / kWaveSize;
    using BVec = opus::vector_t<opus::bf16_t, Vec>;
    using FVec = opus::vector_t<opus::fp32_t, Vec>;

    __shared__ float wave_first[Waves];
    __shared__ float wave_second[Waves];
    __shared__ float block_first;
    __shared__ float block_second;

    const int tid = opus::thread_id_x();
    const int row = opus::block_id_x();
    if(row >= num_tokens)
        return;
    const int base0 = tid * Vec;
    const int base1 = base0 + Threads * Vec;
    const int base2 = base1 + Threads * Vec;
    const int base3 = base2 + Threads * Vec;  // 7168 的尾巴：256*8*3=6144，chunk3 只活 1024

    const auto* prefix = reinterpret_cast<const opus::bf16_t*>(prefix_ptr);
    const auto* blocks = reinterpret_cast<const opus::bf16_t*>(blocks_ptr);
    const auto* norm = reinterpret_cast<const opus::bf16_t*>(norm_weight_ptr);
    const auto* qk = reinterpret_cast<const opus::bf16_t*>(qk_weight_ptr);
    const auto* output_norm =
        reinterpret_cast<const opus::bf16_t*>(output_norm_weight_ptr);
    auto* output = reinterpret_cast<opus::bf16_t*>(output_ptr);
    const long long prefix_row_offset = static_cast<long long>(row) * stride_prefix_m;
    const long long blocks_row_offset = static_cast<long long>(row) * stride_block_m;
    const long long output_row_offset = static_cast<long long>(row) * stride_output_m;

    // [1] 打分权重与 source 无关，先算好，避免在 9 次循环里重复 load norm/qk。
    const FVec input_qk0 =
        bf16x8_to_fp32(load_bf16x8_aligned(norm, base0)) *
        bf16x8_to_fp32(load_bf16x8_aligned(qk, base0));
    const FVec input_qk1 =
        bf16x8_to_fp32(load_bf16x8_aligned(norm, base1)) *
        bf16x8_to_fp32(load_bf16x8_aligned(qk, base1));
    const FVec input_qk2 =
        bf16x8_to_fp32(load_bf16x8_aligned(norm, base2)) *
        bf16x8_to_fp32(load_bf16x8_aligned(qk, base2));
    FVec input_qk3{};
    if(base3 < kK3Hidden)
        input_qk3 = bf16x8_to_fp32(load_bf16x8_aligned(norm, base3)) *
                    bf16x8_to_fp32(load_bf16x8_aligned(qk, base3));

    FVec mixed0{}, mixed1{}, mixed2{}, mixed3{};
    float max_logit = -INFINITY;
    float denominator = 0.0f;
    if constexpr(PrefetchNext)
    {
        // [2] 软件流水：本轮算 source s 时已经发出 s+1 的 load。生产不用这条。
        const auto prefix_resource = __builtin_hcu_make_buffer_rsrc(
            const_cast<opus::bf16_t*>(prefix),
            static_cast<short>(0),
            0x7fffffffu,
            0x00020000u);
        const auto blocks_resource = __builtin_hcu_make_buffer_rsrc(
            const_cast<opus::bf16_t*>(blocks),
            static_cast<short>(0),
            0x7fffffffu,
            0x00020000u);
        BVec raw0{}, raw1{}, raw2{}, raw3{};
        load_k3_exact_source(prefix_resource,
                             blocks_resource,
                             prefix_row_offset,
                             blocks_row_offset,
                             stride_block_r,
                             0,
                             base0,
                             base1,
                             base2,
                             base3,
                             raw0,
                             raw1,
                             raw2,
                             raw3);
#pragma unroll 1
        for(int source = 0; source < kMaxBlocks + 1; ++source)
        {
            BVec next0{}, next1{}, next2{}, next3{};
            if(source < kMaxBlocks)
                load_k3_exact_source(prefix_resource,
                                     blocks_resource,
                                     prefix_row_offset,
                                     blocks_row_offset,
                                     stride_block_r,
                                     source + 1,
                                     base0,
                                     base1,
                                     base2,
                                     base3,
                                     next0,
                                     next1,
                                     next2,
                                     next3);
            const FVec values0 = bf16x8_to_fp32(raw0);
            const FVec values1 = bf16x8_to_fp32(raw1);
            const FVec values2 = bf16x8_to_fp32(raw2);
            const FVec values3 = bf16x8_to_fp32(raw3);
            const float local_square =
                (horizontal_sum8(values0 * values0) +
                 horizontal_sum8(values1 * values1)) +
                (horizontal_sum8(values2 * values2) +
                 horizontal_sum8(values3 * values3));
            const float local_qk =
                (horizontal_sum8(values0 * input_qk0) +
                 horizontal_sum8(values1 * input_qk1)) +
                (horizontal_sum8(values2 * input_qk2) +
                 horizontal_sum8(values3 * input_qk3));
            const auto sums = block_reduce_pair_dpp_scalar<Waves>(local_square,
                                                                   local_qk,
                                                                   wave_first,
                                                                   wave_second,
                                                                   &block_first,
                                                                   &block_second);
            const float score = sums[1] * rsqrtf(sums[0] / kK3Hidden + eps);
            if(source == 0)
            {
                max_logit = score;
                denominator = 1.0f;
                mixed0 = values0;
                mixed1 = values1;
                mixed2 = values2;
                mixed3 = values3;
            }
            else if constexpr(SingleExp)
            {
                // 多数 source 比当前 max 小，只做一次 exp；翻转 max 时再补一次。
                if(score <= max_logit)
                {
                    const float source_scale = expf(score - max_logit);
                    denominator += source_scale;
                    mixed0 += values0 * source_scale;
                    mixed1 += values1 * source_scale;
                    mixed2 += values2 * source_scale;
                    mixed3 += values3 * source_scale;
                }
                else
                {
                    const float old_scale = expf(max_logit - score);
                    denominator = denominator * old_scale + 1.0f;
                    mixed0 = mixed0 * old_scale + values0;
                    mixed1 = mixed1 * old_scale + values1;
                    mixed2 = mixed2 * old_scale + values2;
                    mixed3 = mixed3 * old_scale + values3;
                    max_logit = score;
                }
            }
            else
            {
                const float new_max_logit = fmaxf(max_logit, score);
                const float old_scale = expf(max_logit - new_max_logit);
                const float source_scale = expf(score - new_max_logit);
                denominator = denominator * old_scale + source_scale;
                mixed0 = mixed0 * old_scale + values0 * source_scale;
                mixed1 = mixed1 * old_scale + values1 * source_scale;
                mixed2 = mixed2 * old_scale + values2 * source_scale;
                mixed3 = mixed3 * old_scale + values3 * source_scale;
                max_logit = new_max_logit;
            }
            raw0 = next0;
            raw1 = next1;
            raw2 = next2;
            raw3 = next3;
        }
    }
    else
    {
        // [2] 生产路径：一次一个 source。load、打分、在线 softmax、累加 mixed 全在这一圈。
#pragma unroll 1
        for(int source = 0; source < kMaxBlocks + 1; ++source)
        {
        BVec raw0;
        BVec raw1;
        BVec raw2;
        BVec raw3{};
        if(source == kMaxBlocks)
        {
            raw0 = load_bf16x8_aligned(prefix, prefix_row_offset + base0);
            raw1 = load_bf16x8_aligned(prefix, prefix_row_offset + base1);
            raw2 = load_bf16x8_aligned(prefix, prefix_row_offset + base2);
            if(base3 < kK3Hidden)
                raw3 = load_bf16x8_aligned(prefix, prefix_row_offset + base3);
        }
        else
        {
            const long long source_offset =
                blocks_row_offset + static_cast<long long>(source) * stride_block_r;
            raw0 = load_bf16x8_aligned(blocks, source_offset + base0);
            raw1 = load_bf16x8_aligned(blocks, source_offset + base1);
            raw2 = load_bf16x8_aligned(blocks, source_offset + base2);
            if(base3 < kK3Hidden)
                raw3 = load_bf16x8_aligned(blocks, source_offset + base3);
        }
        const FVec values0 = bf16x8_to_fp32(raw0);
        const FVec values1 = bf16x8_to_fp32(raw1);
        const FVec values2 = bf16x8_to_fp32(raw2);
        const FVec values3 = bf16x8_to_fp32(raw3);
        const float local_square =
            (horizontal_sum8(values0 * values0) +
             horizontal_sum8(values1 * values1)) +
            (horizontal_sum8(values2 * values2) +
             horizontal_sum8(values3 * values3));
        const float local_qk =
            (horizontal_sum8(values0 * input_qk0) +
             horizontal_sum8(values1 * input_qk1)) +
            (horizontal_sum8(values2 * input_qk2) +
             horizontal_sum8(values3 * input_qk3));
        const auto sums = block_reduce_pair_dpp_scalar<Waves>(local_square,
                                                               local_qk,
                                                               wave_first,
                                                               wave_second,
                                                               &block_first,
                                                               &block_second);
        const float score = sums[1] * rsqrtf(sums[0] / kK3Hidden + eps);
        if(source == 0)
        {
            max_logit = score;
            denominator = 1.0f;
            mixed0 = values0;
            mixed1 = values1;
            mixed2 = values2;
            mixed3 = values3;
        }
        else
        {
            if constexpr(SingleExp)
            {
                // Prefill：常见路径只 exp 一次；LargeBatch 走下面双 exp，省掉分支。
                if(score <= max_logit)
                {
                    const float source_scale = expf(score - max_logit);
                    denominator += source_scale;
                    mixed0 += values0 * source_scale;
                    mixed1 += values1 * source_scale;
                    mixed2 += values2 * source_scale;
                    mixed3 += values3 * source_scale;
                }
                else
                {
                    const float old_scale = expf(max_logit - score);
                    denominator = denominator * old_scale + 1.0f;
                    mixed0 = mixed0 * old_scale + values0;
                    mixed1 = mixed1 * old_scale + values1;
                    mixed2 = mixed2 * old_scale + values2;
                    mixed3 = mixed3 * old_scale + values3;
                    max_logit = score;
                }
            }
            else
            {
                const float new_max_logit = fmaxf(max_logit, score);
                const float old_scale = expf(max_logit - new_max_logit);
                const float source_scale = expf(score - new_max_logit);
                denominator = denominator * old_scale + source_scale;
                mixed0 = mixed0 * old_scale + values0 * source_scale;
                mixed1 = mixed1 * old_scale + values1 * source_scale;
                mixed2 = mixed2 * old_scale + values2 * source_scale;
                mixed3 = mixed3 * old_scale + values3 * source_scale;
                max_logit = new_max_logit;
            }
        }
        }
    }

    // [3] mixed 仍带着 softmax 分子。折叠 RMSNorm 把 /denominator 并进 rsqrt，少一遍 hidden。
    if constexpr(!FoldOutputNorm)
    {
        const float inv_denominator = 1.0f / denominator;
        mixed0 *= inv_denominator;
        mixed1 *= inv_denominator;
        mixed2 *= inv_denominator;
        mixed3 *= inv_denominator;
    }
    const float local_output_square =
        (horizontal_sum8(mixed0 * mixed0) + horizontal_sum8(mixed1 * mixed1)) +
        (horizontal_sum8(mixed2 * mixed2) + horizontal_sum8(mixed3 * mixed3));
    const auto output_sums = block_reduce_pair_dpp_scalar<Waves>(
        local_output_square,
        0.0f,
        wave_first,
        wave_second,
        &block_first,
        &block_second);
    const float output_inv = FoldOutputNorm
                                 ? rsqrtf(output_sums[0] / kK3Hidden +
                                          output_norm_eps * denominator * denominator)
                                 : rsqrtf(output_sums[0] / kK3Hidden + output_norm_eps);

    const FVec output0 = mixed0 * output_inv *
                         bf16x8_to_fp32(load_bf16x8_aligned(output_norm, base0));
    const FVec output1 = mixed1 * output_inv *
                         bf16x8_to_fp32(load_bf16x8_aligned(output_norm, base1));
    const FVec output2 = mixed2 * output_inv *
                         bf16x8_to_fp32(load_bf16x8_aligned(output_norm, base2));
    if constexpr(BufferStore)
    {
        const auto output_resource = __builtin_hcu_make_buffer_rsrc(
            output, static_cast<short>(0), 0x7fffffffu, 0x00020000u);
        const int output_row_byte_offset =
            static_cast<int>(output_row_offset * sizeof(opus::bf16_t));
        store_bf16x8_buffer(output_resource,
                            output_row_byte_offset + base0 * sizeof(opus::bf16_t),
                            fp32x8_to_bf16_rne(output0));
        store_bf16x8_buffer(output_resource,
                            output_row_byte_offset + base1 * sizeof(opus::bf16_t),
                            fp32x8_to_bf16_rne(output1));
        store_bf16x8_buffer(output_resource,
                            output_row_byte_offset + base2 * sizeof(opus::bf16_t),
                            fp32x8_to_bf16_rne(output2));
        if(base3 < kK3Hidden)
        {
            const FVec output3 = mixed3 * output_inv *
                                 bf16x8_to_fp32(load_bf16x8_aligned(output_norm, base3));
            store_bf16x8_buffer(output_resource,
                                output_row_byte_offset +
                                    base3 * sizeof(opus::bf16_t),
                                fp32x8_to_bf16_rne(output3));
        }
    }
    else
    {
        store_bf16x8_aligned(
            output, output_row_offset + base0, fp32x8_to_bf16_rne(output0));
        store_bf16x8_aligned(
            output, output_row_offset + base1, fp32x8_to_bf16_rne(output1));
        store_bf16x8_aligned(
            output, output_row_offset + base2, fp32x8_to_bf16_rne(output2));
        if(base3 < kK3Hidden)
        {
            const FVec output3 = mixed3 * output_inv *
                                 bf16x8_to_fp32(load_bf16x8_aligned(output_norm, base3));
            store_bf16x8_aligned(
                output, output_row_offset + base3, fp32x8_to_bf16_rne(output3));
        }
    }
#else
    (void)prefix_ptr;
    (void)blocks_ptr;
    (void)norm_weight_ptr;
    (void)qk_weight_ptr;
    (void)output_norm_weight_ptr;
    (void)output_ptr;
    (void)stride_prefix_m;
    (void)stride_block_m;
    (void)stride_block_r;
    (void)stride_output_m;
    (void)num_tokens;
    (void)eps;
    (void)output_norm_eps;
#endif
}

template <bool SingleExp,
          bool FoldOutputNorm,
          bool PrefetchNext = false,
          bool BufferStore = false>
void launch_opus_k3_attn_res_fast_256x1_register(
    const void* prefix,
    const void* blocks,
    const void* norm_weight,
    const void* qk_weight,
    const void* output_norm_weight,
    void* output,
    long long stride_prefix_m,
    long long stride_block_m,
    long long stride_block_r,
    long long stride_output_m,
    int num_tokens,
    float eps,
    float output_norm_eps,
    hipStream_t stream)
{
    hipLaunchKernelGGL((opus_k3_attn_res_fast_256x1_register_kernel<SingleExp,
                                                                   FoldOutputNorm,
                                                                   PrefetchNext,
                                                                   BufferStore>),
                       dim3(num_tokens),
                       dim3(256),
                       0,
                       stream,
                       prefix,
                       blocks,
                       norm_weight,
                       qk_weight,
                       output_norm_weight,
                       output,
                       stride_prefix_m,
                       stride_block_m,
                       stride_block_r,
                       stride_output_m,
                       num_tokens,
                       eps,
                       output_norm_eps);
}

// AlignedGeneral（原 19）：对齐通用接口，mutation 形状编译期钉死。
// ``DeltaMode``/``BlockWriteMode`` select the prefix-mutation shape: -1 keeps
// the historical runtime test, 0 proves the mutation absent and 1 proves it
// present. Making both compile-time lets the source loop drop its per-iteration
// ``source == block_write_idx`` compare and lets the delta add/store fold into
// straight-line code, which is what the mutating call sites actually need.
template <int NumBlocks,
          bool NoMutation,
          int OutputNormMode,
          int DeltaMode      = -1,
          int BlockWriteMode = -1,
          int HiddenSize     = 0,
          int Threads        = 256,
          int SourceTile     = 1>
__global__ void __launch_bounds__(Threads, 1)
opus_k3_attn_res_general_256x1_register_kernel(
    void* prefix_ptr,
    const void* delta_ptr,
    void* blocks_ptr,
    const void* norm_weight_ptr,
    const void* qk_weight_ptr,
    const void* output_norm_weight_ptr,
    void* output_ptr,
    long long stride_prefix_m,
    long long stride_delta_m,
    long long stride_block_m,
    long long stride_block_r,
    long long stride_output_m,
    int num_tokens,
    int hidden_size,
    int block_write_idx,
    float eps,
    float output_norm_eps,
    bool has_delta,
    bool apply_output_norm)
{
#if defined(__HIP_DEVICE_COMPILE__) && (defined(__gfx936__) || defined(__gfx946__))
    static_assert(NumBlocks >= 0 && NumBlocks <= kMaxBlocks);
    static_assert(OutputNormMode >= -1 && OutputNormMode <= 1);
    static_assert(DeltaMode >= -1 && DeltaMode <= 1);
    static_assert(BlockWriteMode >= -1 && BlockWriteMode <= 1);
    static_assert(Threads == 256 || Threads == 512);
    static_assert(HiddenSize == 0 || (HiddenSize % 8 == 0 && HiddenSize <= kMaxHidden));
    static_assert(SourceTile == 1 || SourceTile == 4);
    static_assert(SourceTile == 1 || (HiddenSize > 0 && Threads == 512),
                  "SourceTile>1 is the 4096 decode path: pinned hidden, 512 threads");
    static_assert(!NoMutation || (DeltaMode <= 0 && BlockWriteMode <= 0),
                  "NoMutation instances must not claim a delta or block write");
    constexpr int Vec = 8;
    constexpr int Waves = Threads / kWaveSize;
    constexpr int kChunk = Threads * Vec;
    constexpr bool kLive0 = HiddenSize <= 0 || 0 * kChunk < HiddenSize;
    constexpr bool kLive1 = HiddenSize <= 0 || 1 * kChunk < HiddenSize;
    constexpr bool kLive2 = HiddenSize <= 0 || 2 * kChunk < HiddenSize;
    constexpr bool kLive3 = HiddenSize <= 0 || 3 * kChunk < HiddenSize;
    using BVec = opus::vector_t<opus::bf16_t, Vec>;
    using FVec = opus::vector_t<opus::fp32_t, Vec>;

    __shared__ float wave_first[SourceTile * Waves];
    __shared__ float wave_second[SourceTile * Waves];
    __shared__ float block_first[SourceTile];
    __shared__ float block_second[SourceTile];

    const int tid = opus::thread_id_x();
    const int row = opus::block_id_x();
    if(row >= num_tokens)
        return;
    const int base0 = tid * Vec;
    const int base1 = base0 + kChunk;
    const int base2 = base1 + kChunk;
    const int base3 = base2 + kChunk;
    const int hidden = HiddenSize > 0 ? HiddenSize : hidden_size;

    auto* prefix = reinterpret_cast<opus::bf16_t*>(prefix_ptr);
    const auto* delta = reinterpret_cast<const opus::bf16_t*>(delta_ptr);
    auto* blocks = reinterpret_cast<opus::bf16_t*>(blocks_ptr);
    const auto* norm = reinterpret_cast<const opus::bf16_t*>(norm_weight_ptr);
    const auto* qk = reinterpret_cast<const opus::bf16_t*>(qk_weight_ptr);
    const auto* output_norm =
        reinterpret_cast<const opus::bf16_t*>(output_norm_weight_ptr);
    auto* output = reinterpret_cast<opus::bf16_t*>(output_ptr);
    const long long prefix_row_offset = static_cast<long long>(row) * stride_prefix_m;
    const long long delta_row_offset = static_cast<long long>(row) * stride_delta_m;
    const long long blocks_row_offset = static_cast<long long>(row) * stride_block_m;
    const long long output_row_offset = static_cast<long long>(row) * stride_output_m;
    const long long block_write_offset =
        blocks_row_offset + static_cast<long long>(block_write_idx) * stride_block_r;
    const bool do_output_norm =
        OutputNormMode < 0 ? apply_output_norm : OutputNormMode == 1;
    // Resolved to a literal whenever the caller pinned the mode, so the
    // mutation and source-loop branches below become compile-time decisions.
    const bool do_delta = DeltaMode < 0 ? has_delta : DeltaMode == 1;
    const bool do_block_write =
        BlockWriteMode < 0 ? (block_write_idx >= 0) : BlockWriteMode == 1;

    BVec updated0{}, updated1{}, updated2{}, updated3{};
    if(kLive0 && base0 < hidden)
    {
        updated0 = load_bf16x8_aligned(prefix, prefix_row_offset + base0);
        if constexpr(!NoMutation)
        {
            if(do_delta)
            {
                updated0 = add_bf16x8_rne(
                    updated0, load_bf16x8_aligned(delta, delta_row_offset + base0));
                store_bf16x8_aligned(prefix, prefix_row_offset + base0, updated0);
            }
            if(do_block_write)
                store_bf16x8_aligned(blocks, block_write_offset + base0, updated0);
        }
    }
    if(kLive1 && base1 < hidden)
    {
        updated1 = load_bf16x8_aligned(prefix, prefix_row_offset + base1);
        if constexpr(!NoMutation)
        {
            if(do_delta)
            {
                updated1 = add_bf16x8_rne(
                    updated1, load_bf16x8_aligned(delta, delta_row_offset + base1));
                store_bf16x8_aligned(prefix, prefix_row_offset + base1, updated1);
            }
            if(do_block_write)
                store_bf16x8_aligned(blocks, block_write_offset + base1, updated1);
        }
    }
    if(kLive2 && base2 < hidden)
    {
        updated2 = load_bf16x8_aligned(prefix, prefix_row_offset + base2);
        if constexpr(!NoMutation)
        {
            if(do_delta)
            {
                updated2 = add_bf16x8_rne(
                    updated2, load_bf16x8_aligned(delta, delta_row_offset + base2));
                store_bf16x8_aligned(prefix, prefix_row_offset + base2, updated2);
            }
            if(do_block_write)
                store_bf16x8_aligned(blocks, block_write_offset + base2, updated2);
        }
    }
    if(kLive3 && base3 < hidden)
    {
        updated3 = load_bf16x8_aligned(prefix, prefix_row_offset + base3);
        if constexpr(!NoMutation)
        {
            if(do_delta)
            {
                updated3 = add_bf16x8_rne(
                    updated3, load_bf16x8_aligned(delta, delta_row_offset + base3));
                store_bf16x8_aligned(prefix, prefix_row_offset + base3, updated3);
            }
            if(do_block_write)
                store_bf16x8_aligned(blocks, block_write_offset + base3, updated3);
        }
    }

    FVec mixed0 = bf16x8_to_fp32(updated0);
    FVec mixed1 = bf16x8_to_fp32(updated1);
    FVec mixed2 = bf16x8_to_fp32(updated2);
    FVec mixed3 = bf16x8_to_fp32(updated3);
    float denominator = 1.0f;

    if constexpr(NumBlocks > 0)
    {
        FVec input_qk0{}, input_qk1{}, input_qk2{}, input_qk3{};
        if(kLive0 && base0 < hidden)
            input_qk0 = bf16x8_to_fp32(load_bf16x8_aligned(norm, base0)) *
                        bf16x8_to_fp32(load_bf16x8_aligned(qk, base0));
        if(kLive1 && base1 < hidden)
            input_qk1 = bf16x8_to_fp32(load_bf16x8_aligned(norm, base1)) *
                        bf16x8_to_fp32(load_bf16x8_aligned(qk, base1));
        if(kLive2 && base2 < hidden)
            input_qk2 = bf16x8_to_fp32(load_bf16x8_aligned(norm, base2)) *
                        bf16x8_to_fp32(load_bf16x8_aligned(qk, base2));
        if(kLive3 && base3 < hidden)
            input_qk3 = bf16x8_to_fp32(load_bf16x8_aligned(norm, base3)) *
                        bf16x8_to_fp32(load_bf16x8_aligned(qk, base3));

        if constexpr(SourceTile == 1)
        {
            float max_logit = -INFINITY;
#pragma unroll 1
            for(int source = 0; source < NumBlocks + 1; ++source)
            {
                BVec raw0{}, raw1{}, raw2{}, raw3{};
                // When the block write is proven absent the only prefix source is
                // the trailing one, so this collapses to a compile-time test and
                // the loop stops re-comparing against block_write_idx.
                const bool use_prefix =
                    source == NumBlocks ||
                    (!NoMutation && do_block_write && source == block_write_idx);
                if(use_prefix)
                {
                    raw0 = updated0;
                    raw1 = updated1;
                    raw2 = updated2;
                    raw3 = updated3;
                }
                else
                {
                    const long long source_offset =
                        blocks_row_offset + static_cast<long long>(source) * stride_block_r;
                    if(kLive0 && base0 < hidden)
                        raw0 = load_bf16x8_aligned(blocks, source_offset + base0);
                    if(kLive1 && base1 < hidden)
                        raw1 = load_bf16x8_aligned(blocks, source_offset + base1);
                    if(kLive2 && base2 < hidden)
                        raw2 = load_bf16x8_aligned(blocks, source_offset + base2);
                    if(kLive3 && base3 < hidden)
                        raw3 = load_bf16x8_aligned(blocks, source_offset + base3);
                }
                const FVec values0 = bf16x8_to_fp32(raw0);
                const FVec values1 = bf16x8_to_fp32(raw1);
                const FVec values2 = bf16x8_to_fp32(raw2);
                const FVec values3 = bf16x8_to_fp32(raw3);
                const float local_square =
                    (horizontal_sum8(values0 * values0) +
                     horizontal_sum8(values1 * values1)) +
                    (horizontal_sum8(values2 * values2) +
                     horizontal_sum8(values3 * values3));
                const float local_qk =
                    (horizontal_sum8(values0 * input_qk0) +
                     horizontal_sum8(values1 * input_qk1)) +
                    (horizontal_sum8(values2 * input_qk2) +
                     horizontal_sum8(values3 * input_qk3));
                const auto sums = block_reduce_pair_dpp_scalar<Waves>(local_square,
                                                                       local_qk,
                                                                       wave_first,
                                                                       wave_second,
                                                                       block_first,
                                                                       block_second);
                const float score = sums[1] * rsqrtf(sums[0] / hidden + eps);
                if(source == 0)
                {
                    max_logit = score;
                    denominator = 1.0f;
                    mixed0 = values0;
                    mixed1 = values1;
                    mixed2 = values2;
                    mixed3 = values3;
                }
                else if(score <= max_logit)
                {
                    const float source_scale = expf(score - max_logit);
                    denominator += source_scale;
                    mixed0 += values0 * source_scale;
                    mixed1 += values1 * source_scale;
                    mixed2 += values2 * source_scale;
                    mixed3 += values3 * source_scale;
                }
                else
                {
                    const float old_scale = expf(max_logit - score);
                    denominator = denominator * old_scale + 1.0f;
                    mixed0 = mixed0 * old_scale + values0;
                    mixed1 = mixed1 * old_scale + values1;
                    mixed2 = mixed2 * old_scale + values2;
                    mixed3 = mixed3 * old_scale + values3;
                    max_logit = score;
                }
            }
        }
        else
        {
            // Triton BLOCK_L: several sources per round, online softmax across
            // the tile. The round loop stays rolled; static_for unrolls only
            // the tile. Unrolling the whole source loop spilled on 7168.
            constexpr int NumSources = NumBlocks + 1;
            constexpr int Rounds = (NumSources + SourceTile - 1) / SourceTile;
            mixed0 = {};
            mixed1 = {};
            mixed2 = {};
            mixed3 = {};
            float max_logit = -INFINITY;
            denominator = 0.0f;
#pragma unroll 1
            for(int round = 0; round < Rounds; ++round)
            {
                const int first_source = round * SourceTile;
                BVec raw0[SourceTile]{};
                BVec raw1[SourceTile]{};
                BVec raw2[SourceTile]{};
                BVec raw3[SourceTile]{};
                opus::static_for<SourceTile>([&](auto j) {
                    constexpr int J = decltype(j)::value;
                    const int source = first_source + J;
                    if(source >= NumSources)
                        return;
                    const bool use_prefix =
                        source == NumBlocks ||
                        (!NoMutation && do_block_write && source == block_write_idx);
                    if(use_prefix)
                    {
                        if constexpr(kLive0)
                            raw0[J] = updated0;
                        if constexpr(kLive1)
                            raw1[J] = updated1;
                        if constexpr(kLive2)
                            raw2[J] = updated2;
                        if constexpr(kLive3)
                            raw3[J] = updated3;
                    }
                    else
                    {
                        const long long source_offset =
                            blocks_row_offset +
                            static_cast<long long>(source) * stride_block_r;
                        if constexpr(kLive0)
                        {
                            if(base0 < hidden)
                                raw0[J] = load_bf16x8_aligned(
                                    blocks, source_offset + base0);
                        }
                        if constexpr(kLive1)
                        {
                            if(base1 < hidden)
                                raw1[J] = load_bf16x8_aligned(
                                    blocks, source_offset + base1);
                        }
                        if constexpr(kLive2)
                        {
                            if(base2 < hidden)
                                raw2[J] = load_bf16x8_aligned(
                                    blocks, source_offset + base2);
                        }
                        if constexpr(kLive3)
                        {
                            if(base3 < hidden)
                                raw3[J] = load_bf16x8_aligned(
                                    blocks, source_offset + base3);
                        }
                    }
                });

                float squares[SourceTile]{};
                float dots[SourceTile]{};
                opus::static_for<SourceTile>([&](auto j) {
                    constexpr int J = decltype(j)::value;
                    if constexpr(kLive0)
                    {
                        const FVec values0 = bf16x8_to_fp32(raw0[J]);
                        squares[J] += horizontal_sum8(values0 * values0);
                        dots[J] += horizontal_sum8(values0 * input_qk0);
                    }
                    if constexpr(kLive1)
                    {
                        const FVec values1 = bf16x8_to_fp32(raw1[J]);
                        squares[J] += horizontal_sum8(values1 * values1);
                        dots[J] += horizontal_sum8(values1 * input_qk1);
                    }
                    if constexpr(kLive2)
                    {
                        const FVec values2 = bf16x8_to_fp32(raw2[J]);
                        squares[J] += horizontal_sum8(values2 * values2);
                        dots[J] += horizontal_sum8(values2 * input_qk2);
                    }
                    if constexpr(kLive3)
                    {
                        const FVec values3 = bf16x8_to_fp32(raw3[J]);
                        squares[J] += horizontal_sum8(values3 * values3);
                        dots[J] += horizontal_sum8(values3 * input_qk3);
                    }
                });
                block_reduce_pairs_dpp<SourceTile, Waves>(squares,
                                                          dots,
                                                          wave_first,
                                                          wave_second,
                                                          block_first,
                                                          block_second);

                float score[SourceTile];
                float new_max_logit = max_logit;
                opus::static_for<SourceTile>([&](auto j) {
                    constexpr int J = decltype(j)::value;
                    score[J] = first_source + J < NumSources
                                   ? block_second[J] *
                                         rsqrtf(block_first[J] / hidden + eps)
                                   : -INFINITY;
                    new_max_logit = fmaxf(new_max_logit, score[J]);
                });
                const float old_scale = expf(max_logit - new_max_logit);
                float scale[SourceTile];
                denominator *= old_scale;
                opus::static_for<SourceTile>([&](auto j) {
                    constexpr int J = decltype(j)::value;
                    scale[J] = first_source + J < NumSources
                                   ? expf(score[J] - new_max_logit)
                                   : 0.0f;
                    denominator += scale[J];
                });
                if constexpr(kLive0)
                    mixed0 = mixed0 * old_scale;
                if constexpr(kLive1)
                    mixed1 = mixed1 * old_scale;
                if constexpr(kLive2)
                    mixed2 = mixed2 * old_scale;
                if constexpr(kLive3)
                    mixed3 = mixed3 * old_scale;
                opus::static_for<SourceTile>([&](auto j) {
                    constexpr int J = decltype(j)::value;
                    const float source_scale = scale[J];
                    if constexpr(kLive0)
                        mixed0 += bf16x8_to_fp32(raw0[J]) * source_scale;
                    if constexpr(kLive1)
                        mixed1 += bf16x8_to_fp32(raw1[J]) * source_scale;
                    if constexpr(kLive2)
                        mixed2 += bf16x8_to_fp32(raw2[J]) * source_scale;
                    if constexpr(kLive3)
                        mixed3 += bf16x8_to_fp32(raw3[J]) * source_scale;
                });
                max_logit = new_max_logit;
            }
        }
    }

    float output_scale;
    if(do_output_norm)
    {
        const float local_output_square =
            (horizontal_sum8(mixed0 * mixed0) + horizontal_sum8(mixed1 * mixed1)) +
            (horizontal_sum8(mixed2 * mixed2) + horizontal_sum8(mixed3 * mixed3));
        const auto output_sums = block_reduce_pair_dpp_scalar<Waves>(
            local_output_square,
            0.0f,
            wave_first,
            wave_second,
            block_first,
            block_second);
        output_scale = rsqrtf(output_sums[0] / hidden +
                              output_norm_eps * denominator * denominator);
    }
    else
    {
        output_scale = 1.0f / denominator;
    }

    if(kLive0 && base0 < hidden)
    {
        FVec result = mixed0 * output_scale;
        if(do_output_norm)
            result = result * bf16x8_to_fp32(load_bf16x8_aligned(output_norm, base0));
        store_bf16x8_aligned(
            output, output_row_offset + base0, fp32x8_to_bf16_rne(result));
    }
    if(kLive1 && base1 < hidden)
    {
        FVec result = mixed1 * output_scale;
        if(do_output_norm)
            result = result * bf16x8_to_fp32(load_bf16x8_aligned(output_norm, base1));
        store_bf16x8_aligned(
            output, output_row_offset + base1, fp32x8_to_bf16_rne(result));
    }
    if(kLive2 && base2 < hidden)
    {
        FVec result = mixed2 * output_scale;
        if(do_output_norm)
            result = result * bf16x8_to_fp32(load_bf16x8_aligned(output_norm, base2));
        store_bf16x8_aligned(
            output, output_row_offset + base2, fp32x8_to_bf16_rne(result));
    }
    if(kLive3 && base3 < hidden)
    {
        FVec result = mixed3 * output_scale;
        if(do_output_norm)
            result = result * bf16x8_to_fp32(load_bf16x8_aligned(output_norm, base3));
        store_bf16x8_aligned(
            output, output_row_offset + base3, fp32x8_to_bf16_rne(result));
    }
#else
    (void)prefix_ptr;
    (void)delta_ptr;
    (void)blocks_ptr;
    (void)norm_weight_ptr;
    (void)qk_weight_ptr;
    (void)output_norm_weight_ptr;
    (void)output_ptr;
    (void)stride_prefix_m;
    (void)stride_delta_m;
    (void)stride_block_m;
    (void)stride_block_r;
    (void)stride_output_m;
    (void)num_tokens;
    (void)hidden_size;
    (void)block_write_idx;
    (void)eps;
    (void)output_norm_eps;
    (void)has_delta;
    (void)apply_output_norm;
#endif
}

template <int NumBlocks,
          bool NoMutation,
          int OutputNormMode,
          int DeltaMode      = -1,
          int BlockWriteMode = -1,
          int HiddenSize     = 0,
          int Threads        = 256,
          int SourceTile     = 1>
void launch_opus_k3_attn_res_general_256x1_register(
    void* prefix,
    const void* delta,
    void* blocks,
    const void* norm_weight,
    const void* qk_weight,
    const void* output_norm_weight,
    void* output,
    long long stride_prefix_m,
    long long stride_delta_m,
    long long stride_block_m,
    long long stride_block_r,
    long long stride_output_m,
    int num_tokens,
    int hidden_size,
    int block_write_idx,
    float eps,
    float output_norm_eps,
    bool has_delta,
    bool apply_output_norm,
    hipStream_t stream)
{
    hipLaunchKernelGGL(
        (opus_k3_attn_res_general_256x1_register_kernel<NumBlocks,
                                                        NoMutation,
                                                        OutputNormMode,
                                                        DeltaMode,
                                                        BlockWriteMode,
                                                        HiddenSize,
                                                        Threads,
                                                        SourceTile>),
                       dim3(num_tokens),
                       dim3(Threads),
                       0,
                       stream,
                       prefix,
                       delta,
                       blocks,
                       norm_weight,
                       qk_weight,
                       output_norm_weight,
                       output,
                       stride_prefix_m,
                       stride_delta_m,
                       stride_block_m,
                       stride_block_r,
                       stride_output_m,
                       num_tokens,
                       hidden_size,
                       block_write_idx,
                       eps,
                       output_norm_eps,
                       has_delta,
                       apply_output_norm);
}

// Decode（原 41）：512 线程 × 3 source/轮，input_qk 留寄存器。
// 下面英文注释保留否决 ID21--36 / 39 / 40 / 42 时的实验记录。
// Kernels 39--42: free registers first, then spend them on fewer source rounds.
//
// Kernels 21--36 all tried to add a live value to kernel 20 and all spilled,
// because kernel 20 has exactly zero register headroom. This goes the other way:
// take a live value away first, and only then widen the source tile that kernel
// 23/25 could not afford (they spilled 232 and 304 bytes at three sources).
//
// The value to remove is input_qk = norm * qk. It is loop invariant, read-only,
// and held as two FP32 vectors, which is 16 VGPRs alive across every round and
// every barrier. Two ways to get rid of it:
//
//   QkMode 1: keep the product in BF16, 8 VGPRs, widen it on use. This is a
//             numerics change -- the product of two BF16 values is exact in FP32
//             and rounding it back to BF16 drops about eight mantissa bits --
//             so it has to be checked against the FP32 reference, not just
//             against Triton. Note this is NOT what kernel 27 did: 27 narrowed
//             the per-source values, which the compiler already did on its own.
//             Keeping the norm and qk operands in BF16 instead would save
//             nothing, since two BF16 vectors cost the same 16 registers as one
//             FP32 vector.
//   QkMode 2: stage the FP32 product in LDS, 0 VGPRs, one ds_read per chunk per
//             round. Every thread reads only the slot it wrote, so no barrier is
//             needed. This is deliberately the same trade the compiler makes
//             when it spills, except LDS is not the private segment: the scratch
//             path is what costs 18 ns per byte, and the 40 bytes of LDS this
//             kernel uses today leave 64 KB free.
//
// SourceTile 3 divides the nine sources evenly into three rounds, which is the
// round count Triton achieves with BLOCK_L=4 and the reason it still leads
// between 46 and 95 tokens.
//
// 流程（生产：SourceTile=3，QkMode=0，input_qk 留 FP32 寄存器）：
//   [1] 预乘 input_qk = norm * qk
//   [2] 每轮并行 load SourceTile 路 source（循环卷起，不展开全部 9 路）
//   [3] 按 chunk 累加平方和 / qk 点积，一次只活一个 chunk 的 qk 向量
//   [4] 多路 DPP 规约 → 本轮共同新 max → 缩放已有 mixed 并累加本轮 source
//   [5] 折叠 output RMSNorm，写回
template <int SourceTile, int QkMode>
__global__ void __launch_bounds__(512, 1)
opus_k3_attn_res_fast_512xn_qk_kernel(const void* prefix_ptr,
                                      const void* blocks_ptr,
                                      const void* norm_weight_ptr,
                                      const void* qk_weight_ptr,
                                      const void* output_norm_weight_ptr,
                                      void* output_ptr,
                                      long long stride_prefix_m,
                                      long long stride_block_m,
                                      long long stride_block_r,
                                      long long stride_output_m,
                                      int num_tokens,
                                      float eps,
                                      float output_norm_eps)
{
#if defined(__HIP_DEVICE_COMPILE__) && (defined(__gfx936__) || defined(__gfx946__))
    constexpr int Threads    = 512;
    constexpr int Vec        = 8;
    constexpr int Chunks     = 2;
    constexpr int Waves      = Threads / kWaveSize;
    constexpr int NumSources = kMaxBlocks + 1;
    constexpr int Rounds     = (NumSources + SourceTile - 1) / SourceTile;
    using BVec               = opus::vector_t<opus::bf16_t, Vec>;
    using FVec               = opus::vector_t<opus::fp32_t, Vec>;

    __shared__ float wave_first[SourceTile * Waves];
    __shared__ float wave_second[SourceTile * Waves];
    __shared__ float block_first[SourceTile];
    __shared__ float block_second[SourceTile];
    constexpr int QkLdsFloats = QkMode == 2 ? Chunks * Threads * Vec : 1;
    __shared__ float qk_lds[QkLdsFloats];

    const int tid = opus::thread_id_x();
    const int row = opus::block_id_x();
    if(row >= num_tokens)
        return;
    // 7168 = 512*8 + 384*8, so chunk 0 is full and chunk 1 is partial.
    const int base0 = tid * Vec;
    const int base1 = base0 + Threads * Vec;
    const bool has1 = base1 < kK3Hidden;

    const auto* prefix = reinterpret_cast<const opus::bf16_t*>(prefix_ptr);
    const auto* blocks = reinterpret_cast<const opus::bf16_t*>(blocks_ptr);
    const auto* norm   = reinterpret_cast<const opus::bf16_t*>(norm_weight_ptr);
    const auto* qk     = reinterpret_cast<const opus::bf16_t*>(qk_weight_ptr);
    const auto* output_norm =
        reinterpret_cast<const opus::bf16_t*>(output_norm_weight_ptr);
    auto* output = reinterpret_cast<opus::bf16_t*>(output_ptr);

    const long long prefix_row = static_cast<long long>(row) * stride_prefix_m;
    const long long blocks_row = static_cast<long long>(row) * stride_block_m;
    const long long output_row = static_cast<long long>(row) * stride_output_m;

    // [1] 7168 拆成两个 chunk。QkMode 0 把 FP32 乘积留在寄存器，跨轮复用。
    FVec input_qk[Chunks];
    BVec input_qk_bf16[Chunks];
    opus::static_for<Chunks>([&](auto c) {
        constexpr int C = decltype(c)::value;
        const int base  = C == 0 ? base0 : base1;
        FVec product{};
        if(C == 0 || has1)
            product = bf16x8_to_fp32(load_bf16x8_aligned(norm, base)) *
                      bf16x8_to_fp32(load_bf16x8_aligned(qk, base));
        if constexpr(QkMode == 0)
            input_qk[C] = product;
        else if constexpr(QkMode == 1)
            input_qk_bf16[C] = fp32x8_to_bf16_rne(product);
        else
        {
            // Private slot per thread, so no barrier is needed before reading.
            float* slot = qk_lds + (C * Threads + tid) * Vec;
            opus::static_for<Vec>([&](auto j) {
                constexpr int J = decltype(j)::value;
                slot[J]         = product[J];
            });
        }
    });

    auto chunk_qk = [&](auto c) -> FVec {
        constexpr int C = decltype(c)::value;
        if constexpr(QkMode == 0)
            return input_qk[C];
        else if constexpr(QkMode == 1)
            return bf16x8_to_fp32(input_qk_bf16[C]);
        else
        {
            const float* slot = qk_lds + (C * Threads + tid) * Vec;
            return FVec{slot[0],
                        slot[1],
                        slot[2],
                        slot[3],
                        slot[4],
                        slot[5],
                        slot[6],
                        slot[7]};
        }
    };

    FVec mixed[Chunks]{};
    float max_logit   = -INFINITY;
    float denominator = 0.0f;

    // [2] 9 个 source 分成 Rounds 轮。#pragma unroll 1 强制卷起，展开会把寄存器打满。
#pragma unroll 1
    for(int round = 0; round < Rounds; ++round)
    {
        const int first_source = round * SourceTile;
        BVec raw[SourceTile][Chunks]{};
        opus::static_for<SourceTile>([&](auto j) {
            constexpr int J = decltype(j)::value;
            const int s     = first_source + J;
            if(s >= NumSources)
                return;
            if(s == kMaxBlocks)
            {
                raw[J][0] = load_bf16x8_aligned(prefix, prefix_row + base0);
                if(has1)
                    raw[J][1] = load_bf16x8_aligned(prefix, prefix_row + base1);
            }
            else
            {
                const long long off =
                    blocks_row + static_cast<long long>(s) * stride_block_r;
                raw[J][0] = load_bf16x8_aligned(blocks, off + base0);
                if(has1)
                    raw[J][1] = load_bf16x8_aligned(blocks, off + base1);
            }
        });

        float squares[SourceTile]{};
        float dots[SourceTile]{};
        // [3] chunk 在外：同一时刻只取出一个 chunk 的 input_qk，压住 VGPR。
        opus::static_for<Chunks>([&](auto c) {
            constexpr int C  = decltype(c)::value;
            const FVec qk_c  = chunk_qk(c);
            opus::static_for<SourceTile>([&](auto j) {
                constexpr int J   = decltype(j)::value;
                const FVec values = bf16x8_to_fp32(raw[J][C]);
                squares[J] += horizontal_sum8(values * values);
                dots[J] += horizontal_sum8(values * qk_c);
            });
        });

        // [4] 本轮 SourceTile 路分数一起规约，用共同新 max 做在线 softmax，避免逐个翻转。
        block_reduce_pairs_dpp<SourceTile, Waves>(
            squares, dots, wave_first, wave_second, block_first, block_second);

        float score[SourceTile];
        float new_max_logit = max_logit;
        opus::static_for<SourceTile>([&](auto j) {
            constexpr int J = decltype(j)::value;
            score[J]        = first_source + J < NumSources
                                  ? block_second[J] *
                                 rsqrtf(block_first[J] / kK3Hidden + eps)
                                  : -INFINITY;
            new_max_logit   = fmaxf(new_max_logit, score[J]);
        });
        const float old_scale = expf(max_logit - new_max_logit);
        float scale[SourceTile];
        denominator *= old_scale;
        opus::static_for<SourceTile>([&](auto j) {
            constexpr int J = decltype(j)::value;
            scale[J]        = first_source + J < NumSources
                                  ? expf(score[J] - new_max_logit)
                                  : 0.0f;
            denominator += scale[J];
        });
        opus::static_for<Chunks>([&](auto c) {
            constexpr int C = decltype(c)::value;
            FVec sum        = mixed[C] * old_scale;
            opus::static_for<SourceTile>([&](auto j) {
                constexpr int J = decltype(j)::value;
                sum             = sum + bf16x8_to_fp32(raw[J][C]) * scale[J];
            });
            mixed[C] = sum;
        });
        max_logit = new_max_logit;
    }

    // [5] mixed 仍是 softmax 分子。rsqrt 里乘上 denominator^2，等价于先归一化再 RMSNorm。
    const float local_output_square =
        horizontal_sum8(mixed[0] * mixed[0]) + horizontal_sum8(mixed[1] * mixed[1]);
    const auto output_sums = block_reduce_pair_dpp_scalar<Waves>(
        local_output_square, 0.0f, wave_first, wave_second, block_first,
        block_second);
    const float output_inv =
        rsqrtf(output_sums[0] / kK3Hidden +
               output_norm_eps * denominator * denominator);

    const FVec out0 = mixed[0] * output_inv *
                      bf16x8_to_fp32(load_bf16x8_aligned(output_norm, base0));
    store_bf16x8_aligned(output, output_row + base0, fp32x8_to_bf16_rne(out0));
    if(has1)
    {
        const FVec out1 =
            mixed[1] * output_inv *
            bf16x8_to_fp32(load_bf16x8_aligned(output_norm, base1));
        store_bf16x8_aligned(output, output_row + base1, fp32x8_to_bf16_rne(out1));
    }
#else
    (void)prefix_ptr;
    (void)blocks_ptr;
    (void)norm_weight_ptr;
    (void)qk_weight_ptr;
    (void)output_norm_weight_ptr;
    (void)output_ptr;
    (void)stride_prefix_m;
    (void)stride_block_m;
    (void)stride_block_r;
    (void)stride_output_m;
    (void)num_tokens;
    (void)eps;
    (void)output_norm_eps;
#endif
}

template <int SourceTile, int QkMode>
void launch_opus_k3_attn_res_fast_512xn_qk(const void* prefix,
                                           const void* blocks,
                                           const void* norm_weight,
                                           const void* qk_weight,
                                           const void* output_norm_weight,
                                           void* output,
                                           long long stride_prefix_m,
                                           long long stride_block_m,
                                           long long stride_block_r,
                                           long long stride_output_m,
                                           int num_tokens,
                                           float eps,
                                           float output_norm_eps,
                                           hipStream_t stream)
{
    hipLaunchKernelGGL((opus_k3_attn_res_fast_512xn_qk_kernel<SourceTile, QkMode>),
                       dim3(num_tokens),
                       dim3(512),
                       0,
                       stream,
                       prefix,
                       blocks,
                       norm_weight,
                       qk_weight,
                       output_norm_weight,
                       output,
                       stride_prefix_m,
                       stride_block_m,
                       stride_block_r,
                       stride_output_m,
                       num_tokens,
                       eps,
                       output_norm_eps);
}

// DecodeSplit（原 37）：14 路切 hidden。下面英文注释保留当时的实验记录。
// Kernel 37: the decode path split across workgroups instead of across registers.
//
// Kernels 21--36 all tried to buy back the exposed memory latency with registers
// and all lost, because kernel 20 already sits exactly at the register budget:
// decode time on gfx936 came out as 17.9 us + 18 ns per byte of private segment
// across seven candidates, so every extra live value costs more scratch traffic
// than the round trip it hides.
//
// What is actually idle is the rest of the device. Every candidate so far uses
// grid = num_tokens, so a decode step of one token runs one workgroup on one of
// the ~60 CUs. The measured evidence that this is the waste: tokens=1 and
// tokens=17 take the same 17.9 us, and at tokens=320 (about 5.3 workgroups per
// CU) each workgroup amortizes to 10.0 us instead of 17.9. A lone workgroup does
// not fill its own CU's memory pipeline; what it lacks is independent work to
// overlap, which costs no registers at all.
//
// Splitting the hidden dimension across workgroups means the two reductions that
// span hidden -- the per-source score and the output RMSNorm -- have to be
// combined across workgroups. The naive form needs three kernels, and an extra
// kernel inside a captured graph was measured at 1.75 us, which leaves no room.
// Two kernels are affordable, and two are enough because the second global
// reduction can be removed analytically: with e_s the softmax numerators and
// mixed_h = sum_s e_s x_{s,h},
//
//     sum_h mixed_h^2 = sum_{s,t} e_s e_t G_{st},   G_{st} = sum_h x_{s,h} x_{t,h}
//
// so if the first kernel also produces the 9x9 Gram matrix of the sources, the
// second kernel gets the output RMSNorm denominator from 54 scalars with no
// communication. G_{ss} is the sum of squares the score already needs.
//
// The price is 46 fused multiply-adds per element in the first kernel instead of
// 2. That trades arithmetic, which is idle here, for memory round trips, which
// are the constraint.
//
// Geometry: SplitBlocks * threads must be 896 for each thread to own exactly one
// eight-element vector, so SplitBlocks fixes the block size. 14 blocks means 64
// threads, one wave, and the first kernel's 54 reductions are then pure DPP with
// no barrier and no LDS. 7 blocks means 128 threads and one cross-wave step, but
// half as many workgroups, which matters because the device retires only about
// 640 of these workgroups concurrently.
//
// The partial sums are written per block and reduced by the second kernel rather
// than atomically accumulated, so there is no non-deterministic summation and no
// zero-fill kernel -- which is exactly the third dispatch that had to go.
constexpr int kSplitSources  = kMaxBlocks + 1;
constexpr int kSplitGram     = kSplitSources * (kSplitSources + 1) / 2;
constexpr int kSplitPartials = kSplitGram + kSplitSources;

// Row-major upper triangle: (0,0)..(0,8) then (1,1)..(1,8) and so on.
constexpr int split_gram_index(int s, int t)
{
    return s * kSplitSources - (s * (s - 1)) / 2 + (t - s);
}

constexpr int split_threads(int split_blocks) { return kK3Hidden / (8 * split_blocks); }

template <int SplitBlocks>
__global__ void __launch_bounds__(split_threads(SplitBlocks))
opus_k3_attn_res_split_score_kernel(const void* prefix_ptr,
                                    const void* blocks_ptr,
                                    const void* norm_weight_ptr,
                                    const void* qk_weight_ptr,
                                    float* partials_ptr,
                                    long long stride_prefix_m,
                                    long long stride_block_m,
                                    long long stride_block_r,
                                    int num_tokens)
{
#if defined(__HIP_DEVICE_COMPILE__) && (defined(__gfx936__) || defined(__gfx946__))
    constexpr int Vec     = 8;
    constexpr int Threads = split_threads(SplitBlocks);
    constexpr int Waves   = Threads / kWaveSize;
    constexpr int Slice   = Threads * Vec;
    using FVec            = opus::vector_t<opus::fp32_t, Vec>;
    static_assert(Slice * SplitBlocks == kK3Hidden, "slices must tile hidden exactly");
    static_assert(Threads % kWaveSize == 0, "block must be whole wave64s");

    const int row = static_cast<int>(opus::block_id_x());
    if(row >= num_tokens)
        return;
    const int slice = static_cast<int>(opus::block_id_y());
    const int tid   = static_cast<int>(opus::thread_id_x());
    const int base  = slice * Slice + tid * Vec;

    const auto* prefix = reinterpret_cast<const opus::bf16_t*>(prefix_ptr);
    const auto* blocks = reinterpret_cast<const opus::bf16_t*>(blocks_ptr);
    const auto* norm   = reinterpret_cast<const opus::bf16_t*>(norm_weight_ptr);
    const auto* qk     = reinterpret_cast<const opus::bf16_t*>(qk_weight_ptr);

    const long long prefix_row = static_cast<long long>(row) * stride_prefix_m;
    const long long blocks_row = static_cast<long long>(row) * stride_block_m;

    // All nine sources plus the two weights go out before anything is consumed,
    // so the whole slice is one round trip deep.
    FVec values[kSplitSources];
    opus::static_for<kMaxBlocks>([&](auto s) {
        constexpr int S = decltype(s)::value;
        values[S]       = bf16x8_to_fp32(load_bf16x8_aligned(
            blocks, blocks_row + static_cast<long long>(S) * stride_block_r + base));
    });
    values[kMaxBlocks] =
        bf16x8_to_fp32(load_bf16x8_aligned(prefix, prefix_row + base));
    const FVec weight = bf16x8_to_fp32(load_bf16x8_aligned(norm, base)) *
                        bf16x8_to_fp32(load_bf16x8_aligned(qk, base));

    float acc[kSplitPartials];
    opus::static_for<kSplitPartials>([&](auto i) { acc[decltype(i)::value] = 0.0f; });
    // Scalar accumulation rather than horizontal_sum8 of a product: one thread
    // owns a single vector, so there is nothing to amortize a tree over and the
    // fused multiply-add chain is half the instructions.
    opus::static_for<kSplitSources>([&](auto s) {
        constexpr int S = decltype(s)::value;
        opus::static_for<kSplitSources>([&](auto t) {
            constexpr int T = decltype(t)::value;
            if constexpr(T >= S)
            {
                constexpr int Idx = split_gram_index(S, T);
                float sum         = 0.0f;
                opus::static_for<Vec>([&](auto j) {
                    constexpr int J = decltype(j)::value;
                    sum += values[S][J] * values[T][J];
                });
                acc[Idx] = sum;
            }
        });
        float dot = 0.0f;
        opus::static_for<Vec>([&](auto j) {
            constexpr int J = decltype(j)::value;
            dot += values[S][J] * weight[J];
        });
        acc[kSplitGram + S] = dot;
    });

    opus::static_for<kSplitPartials>([&](auto i) {
        constexpr int I = decltype(i)::value;
        acc[I]          = wave_reduce_sum_dpp(acc[I]);
    });

    float* out = partials_ptr +
                 (static_cast<long long>(row) * SplitBlocks + slice) * kSplitPartials;
    // wave_reduce_sum_dpp leaves the total in the last lane, not lane 0.
    if constexpr(Waves == 1)
    {
        if(tid == Threads - 1)
            opus::static_for<kSplitPartials>([&](auto i) {
                constexpr int I = decltype(i)::value;
                out[I]          = acc[I];
            });
    }
    else
    {
        __shared__ float staged[Waves][kSplitPartials];
        const int lane = static_cast<int>(opus::lane_id());
        const int wave = tid / kWaveSize;
        if(lane == kWaveSize - 1)
            opus::static_for<kSplitPartials>([&](auto i) {
                constexpr int I  = decltype(i)::value;
                staged[wave][I]  = acc[I];
            });
        opus::sync_threads();
        // One lane per partial, so the handoff buffer is written coalesced.
        if(tid < kSplitPartials)
        {
            float sum = 0.0f;
            for(int w = 0; w < Waves; ++w)
                sum += staged[w][tid];
            out[tid] = sum;
        }
    }
#else
    (void)prefix_ptr;
    (void)blocks_ptr;
    (void)norm_weight_ptr;
    (void)qk_weight_ptr;
    (void)partials_ptr;
    (void)stride_prefix_m;
    (void)stride_block_m;
    (void)stride_block_r;
    (void)num_tokens;
#endif
}

template <int SplitBlocks>
__global__ void __launch_bounds__(split_threads(SplitBlocks))
opus_k3_attn_res_split_mix_kernel(const void* prefix_ptr,
                                  const void* blocks_ptr,
                                  const void* output_norm_weight_ptr,
                                  void* output_ptr,
                                  const float* partials_ptr,
                                  long long stride_prefix_m,
                                  long long stride_block_m,
                                  long long stride_block_r,
                                  long long stride_output_m,
                                  int num_tokens,
                                  float eps,
                                  float output_norm_eps)
{
#if defined(__HIP_DEVICE_COMPILE__) && (defined(__gfx936__) || defined(__gfx946__))
    constexpr int Vec     = 8;
    constexpr int Threads = split_threads(SplitBlocks);
    constexpr int Slice   = Threads * Vec;
    using FVec            = opus::vector_t<opus::fp32_t, Vec>;

    const int row = static_cast<int>(opus::block_id_x());
    if(row >= num_tokens)
        return;
    const int slice = static_cast<int>(opus::block_id_y());
    const int tid   = static_cast<int>(opus::thread_id_x());
    const int base  = slice * Slice + tid * Vec;

    // 54 partials x SplitBlocks, one lane per partial. Every block reduces the
    // same few KB out of L2; that is cheaper than a third kernel.
    __shared__ float totals[kSplitPartials];
    if(tid < kSplitPartials)
    {
        const float* p = partials_ptr +
                         static_cast<long long>(row) * SplitBlocks * kSplitPartials +
                         tid;
        float sum = 0.0f;
        for(int b = 0; b < SplitBlocks; ++b)
            sum += p[b * kSplitPartials];
        totals[tid] = sum;
    }
    opus::sync_threads();

    const auto* prefix = reinterpret_cast<const opus::bf16_t*>(prefix_ptr);
    const auto* blocks = reinterpret_cast<const opus::bf16_t*>(blocks_ptr);
    const auto* output_norm =
        reinterpret_cast<const opus::bf16_t*>(output_norm_weight_ptr);
    auto* output = reinterpret_cast<opus::bf16_t*>(output_ptr);

    const long long prefix_row = static_cast<long long>(row) * stride_prefix_m;
    const long long blocks_row = static_cast<long long>(row) * stride_block_m;
    const long long output_row = static_cast<long long>(row) * stride_output_m;

    // The source loads do not depend on the scalar block below, so issue them
    // first and let the scores be computed while they are in flight.
    FVec values[kSplitSources];
    opus::static_for<kMaxBlocks>([&](auto s) {
        constexpr int S = decltype(s)::value;
        values[S]       = bf16x8_to_fp32(load_bf16x8_aligned(
            blocks, blocks_row + static_cast<long long>(S) * stride_block_r + base));
    });
    values[kMaxBlocks] =
        bf16x8_to_fp32(load_bf16x8_aligned(prefix, prefix_row + base));
    const FVec out_weight =
        bf16x8_to_fp32(load_bf16x8_aligned(output_norm, base));

    float score[kSplitSources];
    float max_logit = -INFINITY;
    opus::static_for<kSplitSources>([&](auto s) {
        constexpr int S     = decltype(s)::value;
        const float squares = totals[split_gram_index(S, S)];
        const float dot     = totals[kSplitGram + S];
        score[S]            = dot * rsqrtf(squares / kK3Hidden + eps);
        max_logit           = fmaxf(max_logit, score[S]);
    });
    float numerator[kSplitSources];
    float denominator = 0.0f;
    opus::static_for<kSplitSources>([&](auto s) {
        constexpr int S = decltype(s)::value;
        numerator[S]    = expf(score[S] - max_logit);
        denominator += numerator[S];
    });

    // sum_h mixed_h^2 from the Gram matrix; off-diagonal terms count twice.
    float mixed_square = 0.0f;
    opus::static_for<kSplitSources>([&](auto s) {
        constexpr int S = decltype(s)::value;
        opus::static_for<kSplitSources>([&](auto t) {
            constexpr int T = decltype(t)::value;
            if constexpr(T >= S)
            {
                const float term =
                    numerator[S] * numerator[T] * totals[split_gram_index(S, T)];
                mixed_square += T == S ? term : 2.0f * term;
            }
        });
    });
    const float output_inv =
        rsqrtf(mixed_square / kK3Hidden +
               output_norm_eps * denominator * denominator);

    FVec mixed{};
    opus::static_for<kSplitSources>([&](auto s) {
        constexpr int S = decltype(s)::value;
        mixed           = mixed + values[S] * numerator[S];
    });
    store_bf16x8_aligned(output,
                         output_row + base,
                         fp32x8_to_bf16_rne(mixed * output_inv * out_weight));
#else
    (void)prefix_ptr;
    (void)blocks_ptr;
    (void)output_norm_weight_ptr;
    (void)output_ptr;
    (void)partials_ptr;
    (void)stride_prefix_m;
    (void)stride_block_m;
    (void)stride_block_r;
    (void)stride_output_m;
    (void)num_tokens;
    (void)eps;
    (void)output_norm_eps;
#endif
}

template <int SplitBlocks>
void launch_opus_k3_attn_res_split(const void* prefix,
                                   const void* blocks,
                                   const void* norm_weight,
                                   const void* qk_weight,
                                   const void* output_norm_weight,
                                   void* output,
                                   float* partials,
                                   long long stride_prefix_m,
                                   long long stride_block_m,
                                   long long stride_block_r,
                                   long long stride_output_m,
                                   int num_tokens,
                                   float eps,
                                   float output_norm_eps,
                                   hipStream_t stream)
{
    const dim3 grid(num_tokens, SplitBlocks);
    hipLaunchKernelGGL((opus_k3_attn_res_split_score_kernel<SplitBlocks>),
                       grid,
                       dim3(split_threads(SplitBlocks)),
                       0,
                       stream,
                       prefix,
                       blocks,
                       norm_weight,
                       qk_weight,
                       partials,
                       stride_prefix_m,
                       stride_block_m,
                       stride_block_r,
                       num_tokens);
    hipLaunchKernelGGL((opus_k3_attn_res_split_mix_kernel<SplitBlocks>),
                       grid,
                       dim3(split_threads(SplitBlocks)),
                       0,
                       stream,
                       prefix,
                       blocks,
                       output_norm_weight,
                       output,
                       partials,
                       stride_prefix_m,
                       stride_block_m,
                       stride_block_r,
                       stride_output_m,
                       num_tokens,
                       eps,
                       output_norm_eps);
}

template <int NumBlocks, int Vec>
void launch_opus_k3_attn_res(void* prefix,
                             const void* delta,
                             void* blocks,
                             const void* norm_weight,
                             const void* qk_weight,
                             const void* output_norm_weight,
                             void* output,
                             long long stride_prefix_m,
                             long long stride_delta_m,
                             long long stride_block_m,
                             long long stride_block_r,
                             long long stride_output_m,
                             int num_tokens,
                             int block_capacity,
                             int hidden_size,
                             int block_write_idx,
                             float eps,
                             float output_norm_eps,
                             bool has_delta,
                             bool apply_output_norm,
                             hipStream_t stream)
{
    hipLaunchKernelGGL((opus_k3_attn_res_kernel<NumBlocks, Vec>),
                       dim3(num_tokens),
                       dim3(kThreads),
                       0,
                       stream,
                       prefix,
                       delta,
                       blocks,
                       norm_weight,
                       qk_weight,
                       output_norm_weight,
                       output,
                       stride_prefix_m,
                       stride_delta_m,
                       stride_block_m,
                       stride_block_r,
                       stride_output_m,
                       num_tokens,
                       block_capacity,
                       hidden_size,
                       block_write_idx,
                       eps,
                       output_norm_eps,
                       has_delta,
                       apply_output_norm);
}

template <int Vec, typename... Args>
void dispatch_num_blocks(int num_blocks, Args&&... args)
{
    switch(num_blocks)
    {
    case 0: launch_opus_k3_attn_res<0, Vec>(std::forward<Args>(args)...); break;
    case 1: launch_opus_k3_attn_res<1, Vec>(std::forward<Args>(args)...); break;
    case 2: launch_opus_k3_attn_res<2, Vec>(std::forward<Args>(args)...); break;
    case 3: launch_opus_k3_attn_res<3, Vec>(std::forward<Args>(args)...); break;
    case 4: launch_opus_k3_attn_res<4, Vec>(std::forward<Args>(args)...); break;
    case 5: launch_opus_k3_attn_res<5, Vec>(std::forward<Args>(args)...); break;
    case 6: launch_opus_k3_attn_res<6, Vec>(std::forward<Args>(args)...); break;
    case 7: launch_opus_k3_attn_res<7, Vec>(std::forward<Args>(args)...); break;
    case 8: launch_opus_k3_attn_res<8, Vec>(std::forward<Args>(args)...); break;
    default: throw std::runtime_error("opus_k3_attn_res: num_blocks must be in [0, 8]");
    }
}

template <int NumBlocks,
          int HiddenSize = 0,
          int Threads    = 256,
          int SourceTile = 1,
          typename... Args>
void launch_selected_general(bool no_mutation,
                             bool apply_output_norm,
                             Args&&... args)
{
    if(no_mutation)
    {
        if(apply_output_norm)
            launch_opus_k3_attn_res_general_256x1_register<NumBlocks,
                                                           true,
                                                           1,
                                                           -1,
                                                           -1,
                                                           HiddenSize,
                                                           Threads,
                                                           SourceTile>(
                std::forward<Args>(args)...);
        else
            launch_opus_k3_attn_res_general_256x1_register<NumBlocks,
                                                           true,
                                                           0,
                                                           -1,
                                                           -1,
                                                           HiddenSize,
                                                           Threads,
                                                           SourceTile>(
                std::forward<Args>(args)...);
    }
    else
    {
        launch_opus_k3_attn_res_general_256x1_register<NumBlocks,
                                                       false,
                                                       -1,
                                                       -1,
                                                       -1,
                                                       HiddenSize,
                                                       Threads,
                                                       SourceTile>(
            std::forward<Args>(args)...);
    }
}

// AlignedGeneral: mutation shape pinned at compile time. The mutating call sites
// (vLLM's MLP attn-res call passes a delta on most layers) otherwise would
// share one fully dynamic instance.
template <int NumBlocks,
          int HiddenSize = 0,
          int Threads    = 256,
          int SourceTile = 1,
          typename... Args>
void launch_selected_general_specialized(bool no_mutation,
                                         bool apply_output_norm,
                                         bool has_delta,
                                         bool has_block_write,
                                         Args&&... args)
{
    if(no_mutation)
    {
        launch_selected_general<NumBlocks, HiddenSize, Threads, SourceTile>(
            true, apply_output_norm, std::forward<Args>(args)...);
        return;
    }
    if(has_delta && !has_block_write)
    {
        if(apply_output_norm)
            launch_opus_k3_attn_res_general_256x1_register<NumBlocks,
                                                           false,
                                                           1,
                                                           1,
                                                           0,
                                                           HiddenSize,
                                                           Threads,
                                                           SourceTile>(
                std::forward<Args>(args)...);
        else
            launch_opus_k3_attn_res_general_256x1_register<NumBlocks,
                                                           false,
                                                           0,
                                                           1,
                                                           0,
                                                           HiddenSize,
                                                           Threads,
                                                           SourceTile>(
                std::forward<Args>(args)...);
    }
    else if(!has_delta && has_block_write)
    {
        if(apply_output_norm)
            launch_opus_k3_attn_res_general_256x1_register<NumBlocks,
                                                           false,
                                                           1,
                                                           0,
                                                           1,
                                                           HiddenSize,
                                                           Threads,
                                                           SourceTile>(
                std::forward<Args>(args)...);
        else
            launch_opus_k3_attn_res_general_256x1_register<NumBlocks,
                                                           false,
                                                           0,
                                                           0,
                                                           1,
                                                           HiddenSize,
                                                           Threads,
                                                           SourceTile>(
                std::forward<Args>(args)...);
    }
    else if(has_delta && has_block_write)
    {
        if(apply_output_norm)
            launch_opus_k3_attn_res_general_256x1_register<NumBlocks,
                                                           false,
                                                           1,
                                                           1,
                                                           1,
                                                           HiddenSize,
                                                           Threads,
                                                           SourceTile>(
                std::forward<Args>(args)...);
        else
            launch_opus_k3_attn_res_general_256x1_register<NumBlocks,
                                                           false,
                                                           0,
                                                           1,
                                                           1,
                                                           HiddenSize,
                                                           Threads,
                                                           SourceTile>(
                std::forward<Args>(args)...);
    }
    else
    {
        if(apply_output_norm)
            launch_opus_k3_attn_res_general_256x1_register<NumBlocks,
                                                           false,
                                                           1,
                                                           0,
                                                           0,
                                                           HiddenSize,
                                                           Threads,
                                                           SourceTile>(
                std::forward<Args>(args)...);
        else
            launch_opus_k3_attn_res_general_256x1_register<NumBlocks,
                                                           false,
                                                           0,
                                                           0,
                                                           0,
                                                           HiddenSize,
                                                           Threads,
                                                           SourceTile>(
                std::forward<Args>(args)...);
    }
}

template <int HiddenSize = 0, int Threads = 256, int SourceTile = 1, typename... Args>
void dispatch_general_num_blocks_specialized(int num_blocks,
                                             bool no_mutation,
                                             bool apply_output_norm,
                                             bool has_delta,
                                             bool has_block_write,
                                             Args&&... args)
{
    switch(num_blocks)
    {
#define OPUS_K3_SPECIALIZED_CASE(N)                                                 \
    case N:                                                                         \
        launch_selected_general_specialized<N, HiddenSize, Threads, SourceTile>(     \
            no_mutation,                                                            \
            apply_output_norm,                                                      \
            has_delta,                                                              \
            has_block_write,                                                        \
            std::forward<Args>(args)...);                                           \
        break;
        OPUS_K3_SPECIALIZED_CASE(0)
        OPUS_K3_SPECIALIZED_CASE(1)
        OPUS_K3_SPECIALIZED_CASE(2)
        OPUS_K3_SPECIALIZED_CASE(3)
        OPUS_K3_SPECIALIZED_CASE(4)
        OPUS_K3_SPECIALIZED_CASE(5)
        OPUS_K3_SPECIALIZED_CASE(6)
        OPUS_K3_SPECIALIZED_CASE(7)
        OPUS_K3_SPECIALIZED_CASE(8)
#undef OPUS_K3_SPECIALIZED_CASE
    default: throw std::runtime_error("opus_k3_attn_res: num_blocks must be in [0, 8]");
    }
}

} // namespace

void opus_k3_attn_res_hcu(torch::Tensor& prefix,
                          torch::Tensor& delta,
                          torch::Tensor& blocks,
                          torch::Tensor& norm_weight,
                          torch::Tensor& qk_weight,
                          torch::Tensor& output_norm_weight,
                          torch::Tensor& output,
                          int num_blocks,
                          int block_write_idx,
                          double eps,
                          double output_norm_eps,
                          int kernel_id)
{
    require(prefix.is_cuda() && blocks.is_cuda() && norm_weight.is_cuda() &&
                qk_weight.is_cuda() && output.is_cuda(),
            "all required tensors must be on a GPU");
    const int device = prefix.get_device();
    const auto runtime_arch = runtime_hcu_arch(device);
    require(runtime_arch == RuntimeHcuArch::Gfx936 ||
                runtime_arch == RuntimeHcuArch::Gfx946,
            "OpusK3AttnResKernel currently supports gfx936 and gfx946");
    auto kernel = static_cast<OpusK3AttnResKernel>(kernel_id);
    require(kernel >= OpusK3AttnResKernel::Auto &&
                kernel <= OpusK3AttnResKernel::LargeBatch,
            "kernelId must be OpusK3AttnResKernel::Auto or a defined kernel");
    require(runtime_arch != RuntimeHcuArch::Gfx946 ||
                kernel == OpusK3AttnResKernel::Auto ||
                kernel == OpusK3AttnResKernel::Fallback ||
                kernel == OpusK3AttnResKernel::AlignedGeneral,
            "gfx946 currently supports AUTO/FALLBACK/ALIGNED_GENERAL only; "
            "other optimized candidates require separate target-specific "
            "correctness gates");
    require(prefix.dim() == 2, "prefix must have shape [tokens, hidden]");
    require(blocks.dim() == 3, "blocks must have shape [tokens, capacity, hidden]");
    require(norm_weight.dim() == 1 && qk_weight.dim() == 1,
            "norm_weight and qk_weight must be 1D");
    require(output.dim() == 2, "output must have shape [tokens, hidden]");
    require(prefix.scalar_type() == at::ScalarType::BFloat16 &&
                blocks.scalar_type() == at::ScalarType::BFloat16 &&
                norm_weight.scalar_type() == at::ScalarType::BFloat16 &&
                qk_weight.scalar_type() == at::ScalarType::BFloat16 &&
                output.scalar_type() == at::ScalarType::BFloat16,
            "prefix, blocks, weights and output must be BF16");
    require(prefix.device() == blocks.device() && prefix.device() == norm_weight.device() &&
                prefix.device() == qk_weight.device() && prefix.device() == output.device(),
            "all required tensors must be on the same GPU");

    const bool has_delta = delta.numel() != 0;
    const bool apply_output_norm = output_norm_weight.numel() != 0;
    if(has_delta)
    {
        require(delta.is_cuda() && delta.device() == prefix.device(),
                "delta must be on the same GPU as prefix");
        require(delta.scalar_type() == at::ScalarType::BFloat16,
                "delta must be BF16");
        require(delta.sizes() == prefix.sizes(), "delta shape must match prefix");
        require(delta.stride(1) == 1, "delta last dimension must be contiguous");
    }
    if(apply_output_norm)
    {
        require(output_norm_weight.is_cuda() && output_norm_weight.device() == prefix.device(),
                "output_norm_weight must be on the same GPU as prefix");
        require(output_norm_weight.scalar_type() == at::ScalarType::BFloat16,
                "output_norm_weight must be BF16");
        require(output_norm_weight.dim() == 1,
                "output_norm_weight must be 1D");
    }

    const int64_t num_tokens = prefix.size(0);
    const int64_t hidden_size = prefix.size(1);
    const int64_t block_capacity = blocks.size(1);
    require(hidden_size > 0 && hidden_size <= kMaxHidden,
            "hidden size must be in [1, 8192]");
    require(num_tokens <= static_cast<int64_t>(UINT32_MAX), "too many tokens for the grid");
    require(blocks.size(0) == num_tokens && blocks.size(2) == hidden_size,
            "blocks shape must be [tokens, capacity, hidden]");
    require(norm_weight.size(0) == hidden_size && qk_weight.size(0) == hidden_size,
            "weight lengths must equal hidden size");
    require(!apply_output_norm || output_norm_weight.size(0) == hidden_size,
            "output_norm_weight length must equal hidden size");
    require(output.sizes() == prefix.sizes(), "output shape must match prefix");
    require(prefix.stride(1) == 1 && blocks.stride(2) == 1 &&
                norm_weight.stride(0) == 1 && qk_weight.stride(0) == 1 &&
                output.is_contiguous(),
            "all tensor last dimensions must be contiguous and output must be contiguous");
    require(num_blocks >= 0 && num_blocks <= kMaxBlocks && num_blocks <= block_capacity,
            "num_blocks must be in [0, min(8, block capacity)]");
    require(block_write_idx == -1 ||
                (block_write_idx >= 0 && block_write_idx < block_capacity),
            "block_write_idx must be -1 or within block capacity");

    if(num_tokens == 0)
        return;

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(prefix));
    const hipStream_t stream = at::hip::getCurrentHIPStream();
    const auto* delta_ptr = has_delta ? delta.data_ptr() : prefix.data_ptr();
    const auto* output_norm_ptr =
        apply_output_norm ? output_norm_weight.data_ptr() : norm_weight.data_ptr();
    const long long delta_stride = has_delta ? delta.stride(0) : 0;

    const bool vectorized = hidden_size % 4 == 0 && prefix.stride(0) % 4 == 0 &&
                            blocks.stride(0) % 4 == 0 && blocks.stride(1) % 4 == 0 &&
                            (!has_delta || delta.stride(0) % 4 == 0) &&
                            is_aligned(prefix.data_ptr(), 8) &&
                            is_aligned(delta_ptr, 8) &&
                            is_aligned(blocks.data_ptr(), 8) &&
                            is_aligned(norm_weight.data_ptr(), 8) &&
                            is_aligned(qk_weight.data_ptr(), 8) &&
                            is_aligned(output_norm_ptr, 8) &&
                            is_aligned(output.data_ptr(), 8);

    const bool vectorized16 = hidden_size % 8 == 0 && prefix.stride(0) % 8 == 0 &&
                              blocks.stride(0) % 8 == 0 &&
                              blocks.stride(1) % 8 == 0 &&
                              (!has_delta || delta.stride(0) % 8 == 0) &&
                              is_aligned(prefix.data_ptr(), 16) &&
                              (!has_delta || is_aligned(delta_ptr, 16)) &&
                              is_aligned(blocks.data_ptr(), 16) &&
                              is_aligned(norm_weight.data_ptr(), 16) &&
                              is_aligned(qk_weight.data_ptr(), 16) &&
                              is_aligned(output_norm_ptr, 16) &&
                              is_aligned(output.data_ptr(), 16);

    if(kernel == OpusK3AttnResKernel::Auto)
    {
        const bool optimized_main_shape =
            hidden_size == kK3Hidden && num_blocks == kMaxBlocks && !has_delta &&
            block_write_idx == -1 && apply_output_norm && vectorized16;
        auto main_shape_kernel = OpusK3AttnResKernel::Prefill;
        if(num_tokens >= kLargeTokenThreshold)
            main_shape_kernel = OpusK3AttnResKernel::LargeBatch;
        else if(num_tokens < kSplitTokenThreshold)
            main_shape_kernel = OpusK3AttnResKernel::DecodeSplit;
        else if(num_tokens < kDecodeTokenThreshold)
            main_shape_kernel = OpusK3AttnResKernel::Decode;
        // gfx946 keeps AUTO on the conservative fallback until real-hardware
        // performance gates pass. Explicit AlignedGeneral is correctness-
        // validated with its target-specific BF16 RNE lowering below.
        kernel = runtime_arch == RuntimeHcuArch::Gfx936
                     ? (optimized_main_shape
                            ? main_shape_kernel
                            : (vectorized16 ? OpusK3AttnResKernel::AlignedGeneral
                                            : OpusK3AttnResKernel::Fallback))
                     : OpusK3AttnResKernel::Fallback;
    }

    if(kernel >= OpusK3AttnResKernel::DecodeSplit &&
       kernel <= OpusK3AttnResKernel::LargeBatch)
    {
        require(hidden_size == kK3Hidden && num_blocks == kMaxBlocks && !has_delta &&
                    block_write_idx == -1 && apply_output_norm && vectorized16,
                "DecodeSplit/Decode/Prefill/LargeBatch require hidden=7168, "
                "num_blocks=8, no delta/block write, output RMSNorm, and 16-byte "
                "aligned contiguous rows");
        if(kernel == OpusK3AttnResKernel::Decode)
        {
            launch_opus_k3_attn_res_fast_512xn_qk<3, 0>(
                prefix.data_ptr(),
                blocks.data_ptr(),
                norm_weight.data_ptr(),
                qk_weight.data_ptr(),
                output_norm_ptr,
                output.data_ptr(),
                static_cast<long long>(prefix.stride(0)),
                static_cast<long long>(blocks.stride(0)),
                static_cast<long long>(blocks.stride(1)),
                static_cast<long long>(output.stride(0)),
                static_cast<int>(num_tokens),
                static_cast<float>(eps),
                static_cast<float>(output_norm_eps),
                stream);
        }
        else if(kernel == OpusK3AttnResKernel::DecodeSplit)
        {
            constexpr int SplitBlocks = 14;
            auto partials =
                at::empty({num_tokens, SplitBlocks, kSplitPartials},
                          prefix.options().dtype(at::ScalarType::Float));
            launch_opus_k3_attn_res_split<SplitBlocks>(
                prefix.data_ptr(),
                blocks.data_ptr(),
                norm_weight.data_ptr(),
                qk_weight.data_ptr(),
                output_norm_ptr,
                output.data_ptr(),
                partials.data_ptr<float>(),
                static_cast<long long>(prefix.stride(0)),
                static_cast<long long>(blocks.stride(0)),
                static_cast<long long>(blocks.stride(1)),
                static_cast<long long>(output.stride(0)),
                static_cast<int>(num_tokens),
                static_cast<float>(eps),
                static_cast<float>(output_norm_eps),
                stream);
        }
        else if(kernel == OpusK3AttnResKernel::Prefill)
            launch_opus_k3_attn_res_fast_256x1_register<true, true>(
                prefix.data_ptr(),
                blocks.data_ptr(),
                norm_weight.data_ptr(),
                qk_weight.data_ptr(),
                output_norm_ptr,
                output.data_ptr(),
                static_cast<long long>(prefix.stride(0)),
                static_cast<long long>(blocks.stride(0)),
                static_cast<long long>(blocks.stride(1)),
                static_cast<long long>(output.stride(0)),
                static_cast<int>(num_tokens),
                static_cast<float>(eps),
                static_cast<float>(output_norm_eps),
                stream);
        else
            launch_opus_k3_attn_res_fast_256x1_register<false, true>(
                prefix.data_ptr(),
                blocks.data_ptr(),
                norm_weight.data_ptr(),
                qk_weight.data_ptr(),
                output_norm_ptr,
                output.data_ptr(),
                static_cast<long long>(prefix.stride(0)),
                static_cast<long long>(blocks.stride(0)),
                static_cast<long long>(blocks.stride(1)),
                static_cast<long long>(output.stride(0)),
                static_cast<int>(num_tokens),
                static_cast<float>(eps),
                static_cast<float>(output_norm_eps),
                stream);
        return;
    }

    if(kernel == OpusK3AttnResKernel::AlignedGeneral)
    {
        require(vectorized16,
                "AlignedGeneral requires hidden and all active row strides to be "
                "multiples of 8 BF16 elements, with 16-byte aligned tensor bases");
        // Triton specializes BLOCK_D=next_power_of_2(hidden), num_warps
        // (8 below 256 tokens, else 4), and BLOCK_L (4 on decode, else 1)
        // at JIT time. AITER compiles one TU, so the same knobs are explicit
        // template instantiations. 4096 is the first pinned hidden; decode
        // also pins SourceTile=4. Other aligned sizes keep HiddenSize=0.
        const int general_threads =
            (num_tokens < 256 && num_blocks > 1) ? 512 : 256;
        if(hidden_size == 4096 && general_threads == 512)
            dispatch_general_num_blocks_specialized<4096, 512, 4>(
                num_blocks,
                !has_delta && block_write_idx == -1,
                apply_output_norm,
                has_delta,
                block_write_idx >= 0,
                prefix.data_ptr(),
                delta_ptr,
                blocks.data_ptr(),
                norm_weight.data_ptr(),
                qk_weight.data_ptr(),
                output_norm_ptr,
                output.data_ptr(),
                static_cast<long long>(prefix.stride(0)),
                delta_stride,
                static_cast<long long>(blocks.stride(0)),
                static_cast<long long>(blocks.stride(1)),
                static_cast<long long>(output.stride(0)),
                static_cast<int>(num_tokens),
                static_cast<int>(hidden_size),
                block_write_idx,
                static_cast<float>(eps),
                static_cast<float>(output_norm_eps),
                has_delta,
                apply_output_norm,
                stream);
        else if(hidden_size == 4096)
            dispatch_general_num_blocks_specialized<4096, 256>(
                num_blocks,
                !has_delta && block_write_idx == -1,
                apply_output_norm,
                has_delta,
                block_write_idx >= 0,
                prefix.data_ptr(),
                delta_ptr,
                blocks.data_ptr(),
                norm_weight.data_ptr(),
                qk_weight.data_ptr(),
                output_norm_ptr,
                output.data_ptr(),
                static_cast<long long>(prefix.stride(0)),
                delta_stride,
                static_cast<long long>(blocks.stride(0)),
                static_cast<long long>(blocks.stride(1)),
                static_cast<long long>(output.stride(0)),
                static_cast<int>(num_tokens),
                static_cast<int>(hidden_size),
                block_write_idx,
                static_cast<float>(eps),
                static_cast<float>(output_norm_eps),
                has_delta,
                apply_output_norm,
                stream);
        else
            dispatch_general_num_blocks_specialized<0, 256>(
                num_blocks,
                !has_delta && block_write_idx == -1,
                apply_output_norm,
                has_delta,
                block_write_idx >= 0,
                prefix.data_ptr(),
                delta_ptr,
                blocks.data_ptr(),
                norm_weight.data_ptr(),
                qk_weight.data_ptr(),
                output_norm_ptr,
                output.data_ptr(),
                static_cast<long long>(prefix.stride(0)),
                delta_stride,
                static_cast<long long>(blocks.stride(0)),
                static_cast<long long>(blocks.stride(1)),
                static_cast<long long>(output.stride(0)),
                static_cast<int>(num_tokens),
                static_cast<int>(hidden_size),
                block_write_idx,
                static_cast<float>(eps),
                static_cast<float>(output_norm_eps),
                has_delta,
                apply_output_norm,
                stream);
        return;
    }

    if(vectorized)
        dispatch_num_blocks<4>(num_blocks,
                               prefix.data_ptr(),
                               delta_ptr,
                               blocks.data_ptr(),
                               norm_weight.data_ptr(),
                               qk_weight.data_ptr(),
                               output_norm_ptr,
                               output.data_ptr(),
                               static_cast<long long>(prefix.stride(0)),
                               delta_stride,
                               static_cast<long long>(blocks.stride(0)),
                               static_cast<long long>(blocks.stride(1)),
                               static_cast<long long>(output.stride(0)),
                               static_cast<int>(num_tokens),
                               static_cast<int>(block_capacity),
                               static_cast<int>(hidden_size),
                               block_write_idx,
                               static_cast<float>(eps),
                               static_cast<float>(output_norm_eps),
                               has_delta,
                               apply_output_norm,
                               stream);
    else
        dispatch_num_blocks<1>(num_blocks,
                               prefix.data_ptr(),
                               delta_ptr,
                               blocks.data_ptr(),
                               norm_weight.data_ptr(),
                               qk_weight.data_ptr(),
                               output_norm_ptr,
                               output.data_ptr(),
                               static_cast<long long>(prefix.stride(0)),
                               delta_stride,
                               static_cast<long long>(blocks.stride(0)),
                               static_cast<long long>(blocks.stride(1)),
                               static_cast<long long>(output.stride(0)),
                               static_cast<int>(num_tokens),
                               static_cast<int>(block_capacity),
                               static_cast<int>(hidden_size),
                               block_write_idx,
                               static_cast<float>(eps),
                               static_cast<float>(output_norm_eps),
                               has_delta,
                               apply_output_norm,
                               stream);
}
