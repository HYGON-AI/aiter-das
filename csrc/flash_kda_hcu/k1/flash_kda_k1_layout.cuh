// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#pragma once

#include "flash_kda_hw_ops.cuh"

namespace kda_detail
{

    inline constexpr int kChunk = 16;
    inline constexpr int kDim = 128;
    inline constexpr int kTile = 16;
    inline constexpr int kWave = 64;

    using Vec4Bf16 =
        __attribute__((__vector_size__(4 * sizeof(unsigned short)))) unsigned short;
    using Vec8Bf16 =
        __attribute__((__vector_size__(8 * sizeof(unsigned short)))) unsigned short;
    using Vec4F32 = __attribute__((__vector_size__(4 * sizeof(float)))) float;

    // FlashKDA 只转换有限递推值：整数 RNE 与有限 FP32→BF16
    // 转换逐位一致，并且避开 DTK 的
    // 指数/NaN 修正控制流。
    __device__ __forceinline__ unsigned short float_to_bf16(float value)
    {
        unsigned int bits;
        __builtin_memcpy(&bits, &value, sizeof(bits));
        const unsigned int lsb = (bits >> 16) & 1u;
        return static_cast<unsigned short>((bits + 0x7fffu + lsb) >> 16);
    }

    // K1 按原生 MMAC A-fragment 顺序写每个逻辑 16x16 tile：
    // [tile, row, group, component]；K2 消费完全相同的物理布局。
    // 模板同时接受 at::BFloat16* 与裸 unsigned short 存储。
    template <typename T>
    __device__ __forceinline__ Vec4Bf16 load_packed_a_fragment(
        const T *matrix, int tile, int row, int group)
    {
        const unsigned short *bits =
            reinterpret_cast<const unsigned short *>(matrix);
        const int offset = tile * kTile * kTile + (row * 4 + group) * 4;
        return *reinterpret_cast<const Vec4Bf16 *>(bits + offset);
    }

    // kd/qd 在现有 LDS 中直接预排，不增加容量或同步点；K2 workspace 契约不变。
    //
    // 自然 K 槽位：物理槽 `group*64 + token*4 + s` 承载逻辑 K = 16*kt + 4*group + s。
    // `packed` 是 `packed_tile_index(token, channel)`（token×K 的 A-fragment 序号），
    // 因此这里只把 (group, s) 两个坐标从 `((c&3), (c%16)/4)` 换成 `((c%16)/4, (c&3))`。
    // 与 token×token 的 `packed_tile_index` 是两件事，不能互相替换。
    __device__ __forceinline__ int kdqd_prelayout_u16(int packed)
    {
        const int local = packed & 255;
        return (packed & ~255) + (local & 3) * 64 + (local >> 4) * 4 + ((local >> 2) & 3);
    }

    // k_inverse 的自然 K 槽位：块内就是 `token*16 + K%16` 的行主序，
    // 与 K2 的 `load_packed_a_fragment` 读法（`row*16 + group*4 + j`）一致。
    __device__ __forceinline__ int k_inverse_natural_index(int key_tile, int token, int key_in_tile)
    {
        return key_tile * kTile * kTile + token * kTile + key_in_tile;
    }

    __device__ __forceinline__ void store_kdqd_pair_lds(
        at::BFloat16 *dst, int packed, unsigned int value)
    {
        const unsigned int address = static_cast<unsigned int>(
            reinterpret_cast<unsigned long long>(dst + kdqd_prelayout_u16(packed)));
        kda_hw::sched_barrier();
        asm volatile("ds_write_b32 %0, %1" ::"v"(address), "v"(value) : "memory");
        kda_hw::sched_barrier();
    }

    __device__ __forceinline__ Vec4Bf16 load_kdqd_a_fragment(
        const at::BFloat16 *src, int tile, int row, int group)
    {
        const unsigned int address = static_cast<unsigned int>(
            reinterpret_cast<unsigned long long>(src + tile * 256 + group * 64 + row * 4));
        Vec4Bf16 value;
        kda_hw::sched_barrier();
        asm volatile("ds_read_b64 %0, %1\n\ts_waitcnt lgkmcnt(0)"
                     : "=v"(value) : "v"(address) : "memory");
        kda_hw::sched_barrier();
        return value;
    }

    template <typename T>
    __device__ __forceinline__ void copy_kdqd_prelayout(
        T *dst, const at::BFloat16 *src, int linear)
    {
        const unsigned int address = static_cast<unsigned int>(
            reinterpret_cast<unsigned long long>(src + linear));
        Vec8Bf16 value;
        kda_hw::sched_barrier();
        asm volatile("ds_read_b128 %0, %1\n\ts_waitcnt lgkmcnt(0)"
                     : "=v"(value) : "v"(address) : "memory");
        kda_hw::sched_barrier();
        asm volatile("global_store_dwordx4 %0, %1, off" ::"v"(dst + linear), "v"(value) : "memory");
        kda_hw::sched_barrier();
    }

    __device__ __forceinline__ Vec4F32 mmac_bf16(
        const Vec4Bf16 &a, const Vec4Bf16 &b, const Vec4F32 &accumulator)
    {
#if defined(__gfx936__)
        // `hcu` 是 DTK 对 gfx936 矩阵指令的内建名。
        return __builtin_hcu_mmac_f32_16x16x16_bf16(a, b, accumulator);
#else
        return accumulator;
#endif
    }

} // namespace kda_detail
