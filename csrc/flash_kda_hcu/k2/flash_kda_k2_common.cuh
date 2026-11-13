// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
//
// K2 的私有公共头：类型、workspace 布局常量、数值转换与 MUBUF 描述符。
// 只被 k2/ 下的实现文件包含，不进入任何公开头。

#ifndef FLASH_KDA_K2_COMMON_CUH
#define FLASH_KDA_K2_COMMON_CUH

#include <ATen/hip/HIPContext.h>
#include <hip/hip_bf16.h>
#include <hip/hip_fp16.h>
#include <hip/hip_runtime.h>
#include <torch/extension.h>

#include <initializer_list>
#include <type_traits>
#include <vector>

#include "flash_kda_fragments.cuh"
#include "flash_kda_intrinsics.cuh"
#include "flash_kda_state_layout.cuh"

namespace
{

    constexpr int kChunkSize = 16; // chunk 长度（token）
    constexpr int kKeyDim = 128;   // K 维
    constexpr int kValueDim = 128; // V 维
    constexpr int kTile = 16;
    constexpr int kK2Waves = 4;   // 每 CTA 的 wave 数
    constexpr int kK2VSlice = 16; // 每 wave 拥有的 V 列

    // kd|qd 合并流：每 chunk 8 KiB，qd 半区相对 kd 半区的偏移 = 4 KiB。
    constexpr int kQdOffsetU16 = kChunkSize * kKeyDim;
    constexpr int kKdqdStrideU16 = 2 * kChunkSize * kKeyDim;
    // kr|gt 合并区：kr 8 个 16x16 tile（4 KiB）+ gt 512 B（正好第 9 个 tile）。
    constexpr int kDecayOffsetU16 = kChunkSize * kKeyDim;
    constexpr int kKrgtStrideU16 = kDecayOffsetU16 + kChunkSize * kChunkSize;

    using u16 = unsigned short;
    using vec4_u16 = flash_kda_k2_fragments::vec4_bf16;
    using vec4_fp32 = flash_kda_k2_fragments::vec4_fp32;

    using flash_kda_k2_fragments::kr_vec4_ptr;
    using flash_kda_k2_fragments::kr_voff;

    // kd/qd 消费顺序：lane(row, group) 在本 tile 内的 u16 偏移。
    __device__ __forceinline__ constexpr int kda_c16_kdqd_cons_u16(int row, int group)
    {
        return group * 64 + row * 4;
    }

    // 第 i 个 16 B 拷贝在 chunk 内的 global 源偏移（区内线性）。
    __device__ __forceinline__ constexpr int kda_c16_kdqd_src16_byte(int i)
    {
        return i * 16;
    }

    __device__ __forceinline__ u16 float_to_bf16_16(float value)
    {
        return flash_kda_k2_fragments::float_to_bf16_rne_fast(value);
    }

    __device__ __forceinline__ float bf16_to_float_16(u16 bits)
    {
        return opus::bf16_to_fp32(__builtin_bit_cast(opus::bf16_t, bits));
    }

    __device__ __forceinline__ u16 float_to_f16_16(float value)
    {
        return flash_kda_k2_fragments::float_to_f16(value);
    }

    void check_c16_tensor(
        const torch::Tensor &tensor,
        const char *name,
        at::ScalarType dtype,
        std::initializer_list<int64_t> shape)
    {
        TORCH_CHECK(tensor.is_cuda(), name, " must be on a GPU");
        TORCH_CHECK(tensor.is_contiguous(), name, " must be contiguous");
        TORCH_CHECK(tensor.scalar_type() == dtype, name, " has wrong dtype");
        TORCH_CHECK(tensor.sizes().vec() == std::vector<int64_t>(shape), name, " has wrong shape");
    }

    // 外部状态的标量类型（只影响入口/出口读写，内部递推恒 FP32）：
    //   StateBf16=false → float；true → u16（BF16 位型，入口左移 16 位精确提升、出口 RNE）。
    template <bool StateBf16>
    struct state_scalar_type
    {
        using type = float;
    };
    template <>
    struct state_scalar_type<true>
    {
        using type = u16;
    };
    template <bool StateBf16>
    using state_scalar_t = typename state_scalar_type<StateBf16>::type;

    __device__ __forceinline__ float bf16_raw_to_float(unsigned int raw)
    {
        return __builtin_bit_cast(float, (raw & 0xffffu) << 16);
    }

    using vec4_u32 = unsigned int __attribute__((ext_vector_type(4)));

    // 从裸 workspace 指针构造 MUBUF 描述符（V#）：word2 = 2 GiB 字节界，够所有 shape。
    __device__ __forceinline__ vec4_u32 kda_c16_make_buffer_rsrc(const void *base)
    {
        const unsigned long long addr = reinterpret_cast<unsigned long long>(base);
        vec4_u32 rsrc;
        rsrc[0] = static_cast<unsigned int>(addr & 0xffffffffull);
        rsrc[1] = static_cast<unsigned int>(addr >> 32);
        rsrc[2] = 0x80000000u;
        rsrc[3] = 0x00020000u;
        return rsrc;
    }

} // namespace

#endif // FLASH_KDA_K2_COMMON_CUH
