// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include <cstdint>

#include <hip/hip_bf16.h>
#include <hip/hip_fp16.h>
#include <hip/hip_runtime.h>

#include "opus/opus.hpp"

// K1 / K2 / 分段三条路径共用的物理 tile 访问、BF16/FP16 MMAC 与 RNE 转换。
namespace flash_kda_k2_fragments
{

    using vec4_bf16 = __attribute__((__vector_size__(4 * sizeof(unsigned short)))) unsigned short;
    using vec4_f16 = __attribute__((__vector_size__(4 * sizeof(unsigned short)))) unsigned short;
    using vec4_fp32 = opus::fp32x4_t;
    // 有限 FP32 值按 RNE 转为 BF16；sNaN 语义随 `opus::fp32_to_bf16_rtn_raw`。
    __device__ __forceinline__ unsigned short float_to_bf16(float value)
    {
        return opus::fp32_to_bf16_rtn_raw(value);
    }

    // 有限 FP32 值按 RNE 转为 BF16；不保证 NaN 的传播语义。
    __device__ __forceinline__ unsigned short float_to_bf16_rne_fast(float value)
    {
        unsigned int bits;
        __builtin_memcpy(&bits, &value, sizeof(bits));
        const unsigned int lsb = (bits >> 16) & 1u;
        return static_cast<unsigned short>((bits + 0x7fffu + lsb) >> 16);
    }
    // 有限 FP32 值按 RNE 转为 FP16。
    __device__ __forceinline__ unsigned short float_to_f16(float value)
    {
        return __builtin_bit_cast(unsigned short, opus::fp32_to_fp16(value));
    }

    // `kr`/`gt` 共享 workspace 的 tile 内布局：`slot = row + 16*group`，相邻 lane
    // 连续 8 B（K2 每 lane 一条 `ds_read_b64`，16 lane 覆盖 bank 0..31 各一次）。
    // K1 写、K2 读、分段读都调用这里的 `kr_*` 函数。
    __device__ __forceinline__ int kr_slot(int row, int group)
    {
        return row + group * 16; // == lane
    }

    // K2 侧：tile 内 per-lane 字节 voffset（每 lane 一条 dwordx2 = 8 B）。
    __device__ __forceinline__ int kr_voff(int row, int group)
    {
        return kr_slot(row, group) * 8;
    }

    __device__ __forceinline__ const unsigned short *kr_vec4_ptr(
        const unsigned short *tile_base, int row, int group)
    {
        return tile_base + kr_slot(row, group) * 4;
    }

    __device__ __forceinline__ unsigned short *kr_vec4_ptr(
        unsigned short *tile_base, int row, int group)
    {
        return tile_base + kr_slot(row, group) * 4;
    }
    __device__ __forceinline__ vec4_fp32 opus_mmac_bf16(
        const vec4_bf16 &a_raw, const vec4_bf16 &b_raw, const vec4_fp32 &c)
    {
        opus::bf16x4_t a{};
        opus::bf16x4_t b{};
#pragma unroll
        for (int i = 0; i < 4; ++i)
        {
            a[i] = a_raw[i];
            b[i] = b_raw[i];
        }
        auto mma = opus::make_tiled_mma<opus::bf16_t, opus::bf16_t, opus::fp32_t>(
            opus::seq<1, 1, 1>{}, opus::seq<1, 1, 1>{}, opus::seq<16, 16, 16>{},
            opus::mmac_adaptor_hcu{});
        return mma(a, b, c);
    }

    __device__ __forceinline__ vec4_fp32 opus_mmac_f16(
        const vec4_f16 &a_raw, const vec4_f16 &b_raw, const vec4_fp32 &c)
    {
        using hcu_fp16x4_t = opus::vector_t<unsigned short, 4>;
        hcu_fp16x4_t a{};
        hcu_fp16x4_t b{};
#pragma unroll
        for (int i = 0; i < 4; ++i)
        {
            a[i] = a_raw[i];
            b[i] = b_raw[i];
        }
        auto mma = opus::make_mfma<opus::fp16_t, opus::fp16_t, opus::fp32_t>(
            opus::seq<16, 16, 16>{}, opus::mmac_adaptor_hcu{});
        return mma(a, b, c);
    }

} // namespace flash_kda_k2_fragments
