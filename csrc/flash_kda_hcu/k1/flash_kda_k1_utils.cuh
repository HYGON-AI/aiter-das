// SPDX-License-Identifier: MIT
//
// peer direct 使用的 device helper；保留原有数值、调度与舍入规则。
#pragma once

#include <ATen/hip/HIPContext.h>
#include <hip/hip_bf16.h>
#include <hip/hip_runtime.h>

#include "flash_kda_k1_layout.cuh"

#include <cmath>
#include <type_traits>

namespace kda_peer
{

    constexpr int kThreads = 256;
    constexpr float kLog2E = 1.4426950408889634f;
    using Vec2F32 = __attribute__((__vector_size__(2 * sizeof(float)))) float;

    using kda_detail::copy_kdqd_prelayout;
    using kda_detail::k_inverse_natural_index;
    using kda_detail::float_to_bf16;
    using kda_detail::kChunk;
    using kda_detail::kDim;
    using kda_detail::kWave;
    using kda_detail::load_kdqd_a_fragment;
    using kda_detail::load_packed_a_fragment;
    using kda_detail::mmac_bf16;
    using kda_detail::store_kdqd_pair_lds;
    using kda_detail::Vec4Bf16;
    using kda_detail::Vec4F32;
    using kda_detail::Vec8Bf16;

    struct PackedQKStorage
    {
        unsigned short q_decayed[kChunk * kDim];
        union
        {
            unsigned short k_decayed[kChunk * kDim];
            float lower_matrix[kChunk * kChunk];
        };
    };

    // 这两个视图在 K1 内生命周期不重叠；用裸 BF16 位型可保持
    // union 平凡，同时具名成员让 LDS 复用显式可见。
    union alignas(16) PrefixQKStorage
    {
        float prefix_log2[kChunk * kDim];
        PackedQKStorage qk;
    };

    static_assert(
        sizeof(PrefixQKStorage) == 2 * kChunk * kDim * sizeof(unsigned short));

    struct InverseScratchStorage
    {
        // 列主序：correction 消费同一列的全部八行。
        unsigned short inverse_a[8 * 8];
        unsigned short inverse_b[8 * 8];
        unsigned short lower_c[8 * 8];
    };

    // KR 恢复在对角求逆开始前消费 end_decay。
    // 两阶段共用同一块 512 B 的 LDS 分配。
    union alignas(16) DecayInverseStorage
    {
        float end_decay[kDim];
        InverseScratchStorage inverse;
    };

    static_assert(sizeof(DecayInverseStorage) == kDim * sizeof(float));

    __device__ __forceinline__ float exp_fast(float value)
    {
#if defined(__gfx936__)
        return __builtin_amdgcn_exp2f(value * kLog2E);
#else
        return expf(value);
#endif
    }

    // gate 前缀已带 log2(e) 缩放，因此沿用与 exp_fast 相同的原生
    // 指数降阶，不再多做一次换底乘法。
    __device__ __forceinline__ float gate_exp2(float prefix_log2)
    {
#if defined(__gfx936__)
        return __builtin_amdgcn_exp2f(prefix_log2);
#else
        return exp2f(prefix_log2);
#endif
    }

    __device__ __forceinline__ float sigmoid(float value)
    {
#if defined(__gfx936__)
        const float denominator =
            1.0f + __builtin_amdgcn_exp2f(-value * kLog2E);
        return __builtin_amdgcn_rcpf(denominator);
#else
        return 1.0f / (1.0f + expf(-value));
#endif
    }

    // beta 的装载与消费分开：sigmoid 准备期间保持裸位型存活，
    // 由消费者通过寄存器输出承担 VM 就绪。
    template <bool BetaBf16>
    __device__ __forceinline__ unsigned int issue_beta_raw(const void *address)
    {
        unsigned int raw;
#if defined(__gfx936__)
        if constexpr (BetaBf16)
            asm volatile("global_load_ushort %0, %1, off"
                         : "=v"(raw) : "v"(address) : "memory");
        else
            asm volatile("global_load_dword %0, %1, off"
                         : "=v"(raw) : "v"(address) : "memory");
#else
        if constexpr (BetaBf16)
            raw = *static_cast<const unsigned short *>(address);
        else
            __builtin_memcpy(&raw, address, sizeof(raw));
#endif
        return raw;
    }

    // 归一化时全部 lane 活跃；小于 16 的 XOR 距离
    // 落在各自的 16-lane 行内，故固定 swizzle 无需边界检查。
    template <int Delta>
    __device__ __forceinline__ float norm_xor(float value)
    {
        static_assert(Delta == 1 || Delta == 2 || Delta == 4 || Delta == 8);
#if defined(__gfx936__)
        int bits;
        __builtin_memcpy(&bits, &value, sizeof(bits));
        // 位模式：每个 32-lane 半区内部 lane' = ((lane & 31) | 0) ^ Delta。
        bits = __builtin_amdgcn_ds_swizzle(bits, 0x001f | (Delta << 10));
        __builtin_memcpy(&value, &bits, sizeof(value));
        return value;
#else
        return __shfl_xor(value, Delta, 16);
#endif
    }

    __device__ __forceinline__ at::BFloat16 multiply_bf16(
        at::BFloat16 lhs, at::BFloat16 rhs)
    {
        const float value = float(lhs) * float(rhs);
        unsigned int bits;
        __builtin_memcpy(&bits, &value, sizeof(bits));
        const unsigned int lsb = (bits >> 16) & 1u;
        const unsigned short rounded =
            static_cast<unsigned short>((bits + 0x7fffu + lsb) >> 16);
        at::BFloat16 result;
        __builtin_memcpy(&result, &rounded, sizeof(rounded));
        return result;
    }

    __device__ __forceinline__ at::BFloat16 make_bf16(float value)
    {
        const unsigned short bits = float_to_bf16(value);
        at::BFloat16 result;
        __builtin_memcpy(&result, &bits, sizeof(bits));
        return result;
    }

    // 8x8 求逆更新保持在整 wave 上；选取更新后的元素
    // 不用发散 EXEC 分支，调用方原有的两次 shuffle 不变。
    __device__ __forceinline__ float select_inverse_update(
        float original, float factor, float pivot_value,
        int row, int column, int pivot)
    {
#if defined(__gfx936__)
        const float accumulated = fmaf(factor, pivot_value, original);
        float result;
        asm volatile(
            "v_cmp_gt_u32_e32 vcc, %6, %5\n\t"
            "v_cndmask_b32_e32 %0, %1, %2, vcc\n\t"
            "v_cmp_eq_u32_e32 vcc, %6, %5\n\t"
            "v_cndmask_b32_e32 %0, %0, %3, vcc\n\t"
            "v_cmp_lt_u32_e32 vcc, %6, %4\n\t"
            "v_cndmask_b32_e32 %0, %1, %0, vcc"
            : "=&v"(result)
            : "v"(original), "v"(accumulated), "v"(factor),
              "v"(row), "v"(column), "s"(pivot)
            : "vcc");
        return result;
#else
        if (row > pivot)
        {
            if (column < pivot)
                return fmaf(factor, pivot_value, original);
            if (column == pivot)
                return factor;
        }
        return original;
#endif
    }

    // 由完整的第一个 wave 调用：八次读都使用同一个已完成
    // BF16 舍入值，故一起发出，并在消费之前统一等待。
    __device__ __forceinline__ void gather_correction_row(
        float value, int row, float (&elements)[8])
    {
#if defined(__gfx936__)
        const unsigned int source_row_bytes = row * 8 * sizeof(float);
        // 寄存器交换不访问 LDS；无关的 LDS
        // 读可以跨这段移动，显式等待收口全部读。
        asm volatile(
            "ds_bpermute_b32 %0, %8, %9 offset:0\n\t"
            "ds_bpermute_b32 %1, %8, %9 offset:4\n\t"
            "ds_bpermute_b32 %2, %8, %9 offset:8\n\t"
            "ds_bpermute_b32 %3, %8, %9 offset:12\n\t"
            "ds_bpermute_b32 %4, %8, %9 offset:16\n\t"
            "ds_bpermute_b32 %5, %8, %9 offset:20\n\t"
            "ds_bpermute_b32 %6, %8, %9 offset:24\n\t"
            "ds_bpermute_b32 %7, %8, %9 offset:28\n\t"
            "s_waitcnt lgkmcnt(0)"
            : "=&v"(elements[0]), "=&v"(elements[1]),
              "=&v"(elements[2]), "=&v"(elements[3]),
              "=&v"(elements[4]), "=&v"(elements[5]),
              "=&v"(elements[6]), "=&v"(elements[7])
            : "v"(source_row_bytes), "v"(value));
#else
#pragma unroll
        for (int d = 0; d < 8; ++d)
            elements[d] = __shfl(value, row * 8 + d, kWave);
#endif
    }

    // 从既有行主序 BF16 8x8 LDS 矩阵读一列；
    // 在本块内收口所有读，避免未完成结果逃出内联汇编。
    __device__ __forceinline__ void load_bc_column(
        const at::BFloat16 *matrix, int column, float (&values)[8])
    {
#if defined(__gfx936__)
        const unsigned int address = static_cast<unsigned int>(
            reinterpret_cast<unsigned long long>(matrix + column));
        unsigned int bits[8];
        asm volatile(
            "ds_read_u16 %0, %8 offset:0\n\t"
            "ds_read_u16 %1, %8 offset:16\n\t"
            "ds_read_u16 %2, %8 offset:32\n\t"
            "ds_read_u16 %3, %8 offset:48\n\t"
            "ds_read_u16 %4, %8 offset:64\n\t"
            "ds_read_u16 %5, %8 offset:80\n\t"
            "ds_read_u16 %6, %8 offset:96\n\t"
            "ds_read_u16 %7, %8 offset:112\n\t"
            "s_waitcnt lgkmcnt(0)"
            : "=&v"(bits[0]), "=&v"(bits[1]), "=&v"(bits[2]), "=&v"(bits[3]),
              "=&v"(bits[4]), "=&v"(bits[5]), "=&v"(bits[6]), "=&v"(bits[7])
            : "v"(address)
            : "memory");
#pragma unroll
        for (int d = 0; d < 8; ++d)
        {
            const unsigned int fp32_bits = bits[d] << 16;
            __builtin_memcpy(&values[d], &fp32_bits, sizeof(fp32_bits));
        }
#else
#pragma unroll
        for (int d = 0; d < 8; ++d)
            values[d] = float(matrix[d * 8 + column]);
#endif
    }

    // 一个 gfx936 16x16 MMAC A fragment 消费的物理布局：
    // 每 lane 拥有的四个元素连续，K2 可用一次向量读取取走。
    __device__ __forceinline__ int packed_tile_index(
        int row, int column, int columns)
    {
        return ((row / kChunk) * (columns / kChunk) + column / kChunk) * (kChunk * kChunk) + ((row & (kChunk - 1)) * 4 + (column & 3)) * 4 + ((column & (kChunk - 1)) >> 2);
    }

} // namespace kda_peer
