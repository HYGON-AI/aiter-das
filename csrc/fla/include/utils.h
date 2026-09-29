// SPDX-License-Identifier: MIT
#pragma once

#include "arch.h"

namespace FLA_NAMESPACE {

#ifndef FLA_BV16_INLINE_K_LDS
#define FLA_BV16_INLINE_K_LDS 1
#endif

#ifndef FLA_BV16_V_TILE_ALL_LANES
#define FLA_BV16_V_TILE_ALL_LANES 1
#endif

#ifndef FLA_BV16_PROJECTION_INLANE_ASM
#define FLA_BV16_PROJECTION_INLANE_ASM 1
#endif

// For dwordx4 LDS loads, WRAP values 0..7 select 16-byte slots. gfx92a
// moves this encoding from M0[18:16] to the low bits of M0[28:24].
#if defined(__gfx92a__)
constexpr int kFlaLdsWrapShift = 24;
#else
constexpr int kFlaLdsWrapShift = 16;
#endif

// Gate/state scaling exp: UseSafeExp clamps x > 0 to 0 with natural exp;
// otherwise UseExp2 selects exp2 vs e^x via HIP multiply + exp2 builtin.
template <bool UseSafeExp, bool UseExp2>
__device__ __forceinline__ float fla_exp(float x)
{
    constexpr float kLog2e = 1.44269504088896340736f;
    if constexpr (UseSafeExp) {
        return x <= 0.0f ? __builtin_amdgcn_exp2f(x * kLog2e) : 0.0f;
    } else if constexpr (UseExp2) {
        return __builtin_amdgcn_exp2f(x);
    } else {
        return __builtin_amdgcn_exp2f(x * kLog2e);
    }
}

__device__ __forceinline__ void
fla_swap_u32(uint32_t &a, uint32_t &b)
{
    const uint32_t tmp = a;
    a = b;
    b = tmp;
}

__device__ __forceinline__ uint32_t
fla_select_group4(const int group, const uint32_t v0, const uint32_t v1,
                  const uint32_t v2, const uint32_t v3)
{
    switch (group & 3) {
    case 0:
        return v0;
    case 1:
        return v1;
    case 2:
        return v2;
    default:
        return v3;
    }
}

__device__ __forceinline__ fla_f32x4
fla_make_gemm0_projection_v4(const fla_f32x4 c0, const int lane_k_group)
{
    // MMAC gives each lane group a strided V pattern:
    //   group a: {V=a, V=4+a, V=8+a, V=12+a}.
    // The residual path wants the contiguous V4 owned by this lane group:
    //   group a: {V=4*a+0, V=4*a+1, V=4*a+2, V=4*a+3}.
    // This is a 4x4 transpose across lane groups.  Keep all lanes executing
    // the same three bpermutes, but avoid dynamic VGPR-array indexing by
    // selecting the send registers with local swaps.
    const uint32_t c0_0 = ck_tile::bit_cast<uint32_t>(c0[0]);
    const uint32_t c0_1 = ck_tile::bit_cast<uint32_t>(c0[1]);
    const uint32_t c0_2 = ck_tile::bit_cast<uint32_t>(c0[2]);
    const uint32_t c0_3 = ck_tile::bit_cast<uint32_t>(c0[3]);

#if FLA_BV16_PROJECTION_INLANE_ASM && \
    (defined(__gfx928__) || defined(__gfx92a__) || defined(__gfx936__) || defined(__gfx938__))
    uint32_t r0 = c0_0;
    uint32_t r1 = c0_1;
    uint32_t r2 = c0_2;
    uint32_t r3 = c0_3;

    const uint32_t lane_id = threadIdx.x & 63;
    const uint32_t bit0 = uint32_t(lane_k_group & 1);
    const uint32_t bit1 = uint32_t(lane_k_group & 2);
    const uint32_t offset_xor16 = (lane_id ^ 16u) << 2;
    const uint32_t offset_xor32 = (lane_id ^ 32u) << 2;
    const uint32_t offset_xor48 = (lane_id ^ 48u) << 2;
    const auto saved_exec = __builtin_amdgcn_read_exec();

    // Implement the same 4x4 lane-group transpose as the C++ fallback, but
    // keep the lane-local register selection under temporary EXEC masks.  The
    // post-swap stage below consumes ds_bpermute results inside this asm block,
    // so the in-asm lgkmcnt wait is required; the compiler cannot infer that
    // dependency across hand-written DS instructions.
    asm volatile(
        "v_cmpx_ne_u32 exec, 0, %[bit0]\n\t"
        "v_swap_b32 %[r0], %[r1]\n\t"
        "v_swap_b32 %[r2], %[r3]\n\t"
        "s_mov_b64 exec, %[saved_exec]\n\t"

        "v_cmpx_ne_u32 exec, 0, %[bit1]\n\t"
        "v_swap_b32 %[r0], %[r2]\n\t"
        "v_swap_b32 %[r1], %[r3]\n\t"
        "s_mov_b64 exec, %[saved_exec]\n\t"

        "ds_bpermute_b32 %[r1], %[offset_xor16], %[r1]\n\t"
        "ds_bpermute_b32 %[r2], %[offset_xor32], %[r2]\n\t"
        "ds_bpermute_b32 %[r3], %[offset_xor48], %[r3]\n\t"
        "s_waitcnt lgkmcnt(0)\n\t"

        "v_cmpx_ne_u32 exec, 0, %[bit0]\n\t"
        "v_swap_b32 %[r0], %[r1]\n\t"
        "v_swap_b32 %[r2], %[r3]\n\t"
        "s_mov_b64 exec, %[saved_exec]\n\t"

        "v_cmpx_ne_u32 exec, 0, %[bit1]\n\t"
        "v_swap_b32 %[r0], %[r2]\n\t"
        "v_swap_b32 %[r1], %[r3]\n\t"
        "s_mov_b64 exec, %[saved_exec]\n\t"
        : [r0] "+v"(r0), [r1] "+v"(r1), [r2] "+v"(r2),
          [r3] "+v"(r3)
        : [bit0] "v"(bit0), [bit1] "v"(bit1),
          [offset_xor16] "v"(offset_xor16),
          [offset_xor32] "v"(offset_xor32),
          [offset_xor48] "v"(offset_xor48),
          [saved_exec] "s"(saved_exec)
        : "memory");

    return fla_f32x4{
        ck_tile::bit_cast<float>(r0),
        ck_tile::bit_cast<float>(r1),
        ck_tile::bit_cast<float>(r2),
        ck_tile::bit_cast<float>(r3)};
#else
    const int group = lane_k_group & 3;
    uint32_t own = c0_0;
    uint32_t send1 = c0_1;
    uint32_t send2 = c0_2;
    uint32_t send3 = c0_3;
    if (group & 1) {
        fla_swap_u32(own, send1);
        fla_swap_u32(send2, send3);
    }
    if (group & 2) {
        fla_swap_u32(own, send2);
        fla_swap_u32(send1, send3);
    }

    const int lane_id = threadIdx.x & 63;
    uint32_t out0 = own;
    uint32_t out1 = fla_ds_bpermute_u32((lane_id ^ 16) << 2, send1);
    uint32_t out2 = fla_ds_bpermute_u32((lane_id ^ 32) << 2, send2);
    uint32_t out3 = fla_ds_bpermute_u32((lane_id ^ 48) << 2, send3);
    if (group & 1) {
        fla_swap_u32(out0, out1);
        fla_swap_u32(out2, out3);
    }
    if (group & 2) {
        fla_swap_u32(out0, out2);
        fla_swap_u32(out1, out3);
    }

    return fla_f32x4{
        ck_tile::bit_cast<float>(out0),
        ck_tile::bit_cast<float>(out1),
        ck_tile::bit_cast<float>(out2),
        ck_tile::bit_cast<float>(out3)};
#endif
}

__device__ __forceinline__ fla_u32x4
fla_make_packed_projection_u32x4(const fla_u32x4 c0,
                                 const int lane_k_group)
{
    const int group = lane_k_group & 3;
    const int lane_id = threadIdx.x & 63;

    const uint32_t own =
        fla_select_group4(group, c0[0], c0[1], c0[2], c0[3]);
    const uint32_t send_xor16 =
        fla_select_group4(group, c0[1], c0[0], c0[3], c0[2]);
    const uint32_t send_xor32 =
        fla_select_group4(group, c0[2], c0[3], c0[0], c0[1]);
    const uint32_t send_xor48 =
        fla_select_group4(group, c0[3], c0[2], c0[1], c0[0]);

    uint32_t recv_xor16 =
        fla_ds_bpermute_u32((lane_id ^ 16) << 2, send_xor16);
    uint32_t recv_xor32 =
        fla_ds_bpermute_u32((lane_id ^ 32) << 2, send_xor32);
    uint32_t recv_xor48 =
        fla_ds_bpermute_u32((lane_id ^ 48) << 2, send_xor48);
    asm volatile("s_waitcnt lgkmcnt(0)\n\t"
                 : "+v"(recv_xor16), "+v"(recv_xor32),
                   "+v"(recv_xor48)
                 :
                 : "memory");

    const uint32_t out0 =
        fla_select_group4(group, own, recv_xor16, recv_xor32, recv_xor48);
    const uint32_t out1 =
        fla_select_group4(group, recv_xor16, own, recv_xor48, recv_xor32);
    const uint32_t out2 =
        fla_select_group4(group, recv_xor32, recv_xor48, own, recv_xor16);
    const uint32_t out3 =
        fla_select_group4(group, recv_xor48, recv_xor32, recv_xor16, own);

    return fla_u32x4{out0, out1, out2, out3};
}

// Plain LDS/local-pointer store (no buffer descriptor, no OOB check) --
// distinct from arch.h's fla_buffer_store_element_v8_vgpr, which targets
// GMEM through a raw buffer descriptor.  Named fla_lds_store_* rather than
// fla_buffer_store_* to avoid confusion between the two address spaces.
template <typename Element>
__device__ __forceinline__ void
fla_lds_store_v8_vector(Element *dst_row, const fla_f32x4 lo,
                        const fla_f32x4 hi)
{
    *reinterpret_cast<fla_u32x4 *>(dst_row) =
        fla_pack_v8_from_f32<Element>(lo, hi);
}

template <typename Element, typename Params, typename Index, int BK,
          int STRIDE, int kThreads, bool NoOob = false>
__device__ __forceinline__ void
fla_store_h_snapshot_v8_from_h_low_kmajor_bv16(
    const Params &params, const int chunk, const int v_begin,
    const Element *__restrict__ h_low_base, Element *__restrict__ h_ptr,
    const int tid)
{
    if constexpr (NoOob && ((16 * BK) / 8 == kThreads)) {
        // For the target BV16 K=128 shape, the snapshot has exactly one V8
        // vector per thread.  Emit a straight-line store so the compiler does
        // not materialize a loop-bound EXEC mask in the steady full-chunk path.
        const int vec_idx = tid;
        const int v_local = vec_idx / (BK / 8);
        const int k_vec = (vec_idx - v_local * (BK / 8)) * 8;
        const int v_col = v_begin + v_local;
        const int logical_group8 = k_vec >> 3;
        const int group_swizzle = v_local & 7;
        const int physical_group8 = logical_group8 ^ group_swizzle;
        const Element *h_src =
            h_low_base + v_local * STRIDE + physical_group8 * 8;
        const fla_u32x4 h_pack =
            *reinterpret_cast<const fla_u32x4 *>(h_src);
        const int32_t h_offset_bytes =
            static_cast<int32_t>((Index(chunk) * params.h_chunk_stride +
                                  Index(v_col) * params.K + k_vec) *
                                 sizeof(Element));
        fla_buffer_store_vgpr<4>(h_ptr, h_offset_bytes, h_pack);
    } else {
#pragma unroll
        for (int vec_idx = tid; vec_idx < (16 * BK) / 8;
             vec_idx += kThreads) {
            const int v_local = vec_idx / (BK / 8);
            const int k_vec = (vec_idx - v_local * (BK / 8)) * 8;
            const int v_col = v_begin + v_local;
            const int logical_group8 = k_vec >> 3;
            const int group_swizzle = v_local & 7;
            const int physical_group8 = logical_group8 ^ group_swizzle;
            const Element *h_src =
                h_low_base + v_local * STRIDE + physical_group8 * 8;
            const fla_u32x4 h_pack =
                *reinterpret_cast<const fla_u32x4 *>(h_src);
            const int32_t h_offset_bytes =
                static_cast<int32_t>((Index(chunk) * params.h_chunk_stride +
                                      Index(v_col) * params.K + k_vec) *
                                     sizeof(Element));
            fla_buffer_store_vgpr<4>(
                h_ptr,
                v_col < params.V ? h_offset_bytes : -1,
                h_pack);
        }
    }
}

template <typename Element, int BV>
__device__ __forceinline__ void
fla_store_v_tile_m32x16_v8_swizzled(Element *tile_base, const int t_local,
                                    const fla_f32x4 lo, const fla_f32x4 hi,
                                    const int lane_k_group)
{
    const int stage = t_local >> 4;
    const int t_in_stage = t_local & 15;
    const int physical_row = lane_k_group + 4 * (t_in_stage & 3);
    const int physical_v = (t_in_stage >> 2) * 8;
    Element *dst = tile_base + stage * 16 * BV + physical_row * BV +
                   physical_v;
    fla_lds_store_v8_vector<Element>(dst, lo, hi);
}

template <typename Element>
__device__ __forceinline__ void
fla_store_v_tile_m32x16_bv16_swizzled(Element *tile_base, const int t_local,
                                      const fla_f32x4 raw_v4,
                                      const int lane_k_group)
{
#if FLA_BV16_V_TILE_ALL_LANES
    const int stage = t_local >> 4;
    const int t_in_stage = t_local & 15;
    const int logical_v8_group = lane_k_group >> 1;
    const int physical_row = logical_v8_group + 4 * (t_in_stage & 3);
    const int physical_v =
        (t_in_stage >> 2) * 8 + (lane_k_group & 1) * 4;
    Element *dst = tile_base + stage * 16 * 32 + physical_row * 32 +
                   physical_v;
    const fla_u32x2 packed = {
        fla_pack_element_x2_bits<Element>(fla_f32x2{raw_v4[0], raw_v4[1]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{raw_v4[2], raw_v4[3]}),
    };
    *reinterpret_cast<fla_u32x2 *>(dst) = packed;
#else
    fla_f32x4 peer_v4;
#pragma unroll
    for (int s = 0; s < 4; ++s) {
        peer_v4[s] = __shfl_xor(raw_v4[s], 16, 64);
    }

    if ((lane_k_group & 1) == 0) {
        const int logical_v8_group = lane_k_group >> 1;
        fla_store_v_tile_m32x16_v8_swizzled<Element, 32>(
            tile_base, t_local, raw_v4, peer_v4, logical_v8_group);
    }
#endif
}

template <typename Element, int BT, int BK, int kNWarps,
          bool CheckBounds = false, int ColumnBegin = 0, int ColumnEnd = -1>
__device__ __forceinline__ void
fla_prefetch_w_to_lds(Element *w_lds_base, const Element *w_gmem_src,
                      const int stride_src, const int valid_t = BT)
{
    constexpr int kThreads = kNWarps * 64;
    constexpr int kElemsPerThread = (BT * BK) / kThreads;
    constexpr int kElemsVec = 16 / sizeof(Element);
    constexpr int kElemsPerAccess =
        kElemsVec < kElemsPerThread ? kElemsVec : kElemsPerThread;
    constexpr int kLanesInColumn =
        (BK / kElemsPerAccess) > 8 ? 8 : (BK / kElemsPerAccess);
    constexpr int kIteratorColumn = BK / (kLanesInColumn * kElemsPerAccess);
    constexpr int kIteratorRow =
        kElemsPerThread / (kIteratorColumn * kElemsPerAccess);
    constexpr int kColumnEnd = ColumnEnd < 0 ? kIteratorColumn : ColumnEnd;
    static_assert(ColumnBegin >= 0 && ColumnBegin < kColumnEnd &&
                  kColumnEnd <= kIteratorColumn);

    using AccessType = __uint128_t;

    const int warp_id = threadIdx.x / 64;
    const int lane_id = threadIdx.x & 63;
    const int lane_offset =
        ((lane_id % kLanesInColumn) * kElemsPerAccess +
         (lane_id / kLanesInColumn) * kNWarps * kIteratorRow * stride_src +
         warp_id * stride_src) *
        sizeof(Element);
    const int warp_lds_offset = warp_id * 64 * kElemsPerAccess * sizeof(Element);

    const AccessType *vec_ptr = reinterpret_cast<const AccessType *>(w_gmem_src);
    const int lds_addr_per_wave =
        static_cast<int>(reinterpret_cast<uintptr_t>(w_lds_base)) +
        warp_lds_offset;

    const fla_i32x4 buffer_rsrc = fla_make_uniform_buffer_rsrc(vec_ptr);
#pragma unroll
    for (int ic = ColumnBegin; ic < kColumnEnd; ++ic) {
        const int col_iterator_offset =
            ic * kLanesInColumn * kElemsPerAccess * sizeof(Element);
#pragma unroll
        for (int ir = 0; ir < kIteratorRow; ++ir) {
            const int row_iterator_offset =
                ir * kNWarps * stride_src * sizeof(Element);
            const int lds_offset =
                64 * kElemsPerAccess * sizeof(Element) *
                (ir + ic * kIteratorRow) * kNWarps;
            const int wrap_offset = (warp_id + ir * kNWarps) << kFlaLdsWrapShift;
            const int target_addr =
                __builtin_amdgcn_readfirstlane(
                    lds_addr_per_wave + lds_offset + wrap_offset);
            int offset_v = col_iterator_offset + row_iterator_offset + lane_offset;
            if constexpr (CheckBounds) {
                const int load_row =
                    warp_id +
                    (lane_id / kLanesInColumn) * kNWarps * kIteratorRow +
                    ir * kNWarps;
                offset_v = load_row < valid_t ? offset_v : -1;
            }
            // Both the steady (no OOB) and tail (OOB via voffset=-1) paths
            // share the inline-asm direct-to-LDS load so the caller owns
            // waitcnt placement.  OOB is expressed by the same hardware
            // descriptor convention (records=0xFFFFFFFE) used everywhere else:
            // voffset=-1 (0xFFFFFFFF) is the only offset that falls outside the
            // descriptor's range, so the inline asm handles it identically to
            // the builtin wrapper.
            fla_buffer_load_dwordx4_to_lds_inline(
                buffer_rsrc, target_addr, offset_v);
        }
    }
}

template <typename Element, int BT, int BK, int kNWarps>
__device__ __forceinline__ fla_u32x4
fla_read_w_stage(Element *w_lds_base, const int k_stage)
{
    const int warp_id = threadIdx.x / 64;
    const int lane_id = threadIdx.x & 63;
    const int logical_row = (lane_id & 15) + warp_id * 16;
    const int logical_col = lane_id >> 4;
    const int partition_row = logical_row & 7;
    const int partition_col = k_stage >> 1;
    const int partition_offset = (partition_row + partition_col * 8) * 64;
    const int in_partition_offset =
        ((logical_row / 8) * 8 + (logical_col + (k_stage & 1) * 4) +
         partition_row) &
        63;
    auto *src = reinterpret_cast<fla_u32x4 *>(w_lds_base);
    return src[partition_offset + in_partition_offset];
}

// Four-wave BV64 GEMM0: every wave owns a BV16 output slice and therefore
// consumes the same W rows.  The physical W image is unchanged; only the
// logical row is selected by the explicit T16 stage instead of warp_id.
template <typename Element, int BT, int BK, int kNWarps>
__device__ __forceinline__ fla_u32x4
fla_read_w_stage_bv64(Element *w_lds_base, const int t_stage,
                      const int k_stage)
{
    const int lane_id = threadIdx.x & 63;
    const int logical_row = t_stage * 16 + (lane_id & 15);
    const int logical_col = lane_id >> 4;
    const int partition_row = logical_row & 7;
    const int partition_col = k_stage >> 1;
    const int partition_offset = (partition_row + partition_col * 8) * 64;
    const int in_partition_offset =
        ((logical_row / 8) * 8 + logical_col + (k_stage & 1) * 4 +
         partition_row) &
        63;
    auto *src = reinterpret_cast<fla_u32x4 *>(w_lds_base);
    return src[partition_offset + in_partition_offset];
}

template <typename Element, int BT, int BK, int kNWarps,
          bool CheckBounds = false, int IterBegin = 0, int IterEnd = -1>
__device__ __forceinline__ void
fla_prefetch_k_to_lds(Element *k_lds_base, const Element *k_gmem_src,
                      const int stride_src, const int valid_t = BT)
{
    constexpr int kThreads = kNWarps * 64;
    constexpr int kElemsPerThread = (BT * BK) / kThreads;
    constexpr int kElemsVec = 16 / sizeof(Element);
    constexpr int kElemsPerAccess =
        kElemsVec < kElemsPerThread ? kElemsVec : kElemsPerThread;
    constexpr int kLanesInColumn = BK / kElemsPerAccess;
    constexpr int kLanesInRow = 64 / kLanesInColumn;
    constexpr int kIteratorColumn = 1;
    constexpr int kIteratorRow =
        kElemsPerThread / (kIteratorColumn * kElemsPerAccess);
    constexpr int kIterEnd = IterEnd < 0 ? kIteratorRow : IterEnd;
    static_assert(IterBegin >= 0 && IterBegin < kIterEnd &&
                  kIterEnd <= kIteratorRow);

    using AccessType = __uint128_t;

    const int warp_id = threadIdx.x / 64;
    const int lane_id = threadIdx.x & 63;
    const int lane_offset =
        ((lane_id % kLanesInColumn) * kElemsPerAccess +
         (lane_id / kLanesInColumn) * kNWarps * stride_src +
         warp_id * stride_src) *
        sizeof(Element);
    const int warp_lds_offset = warp_id * 64 * kElemsPerAccess * sizeof(Element);
    const int wrap_offset = (4 << kFlaLdsWrapShift) * (warp_id & 1);

    const AccessType *vec_ptr = reinterpret_cast<const AccessType *>(k_gmem_src);
    const int lds_addr_per_wave =
        static_cast<int>(reinterpret_cast<uintptr_t>(k_lds_base)) +
        warp_lds_offset + wrap_offset;

    const fla_i32x4 buffer_rsrc = fla_make_uniform_buffer_rsrc(vec_ptr);
#pragma unroll
    for (int ir = IterBegin; ir < kIterEnd; ++ir) {
        const int row_iterator_offset =
            ir * kLanesInRow * kNWarps * stride_src * sizeof(Element);
        const int lds_offset =
            64 * kElemsPerAccess * sizeof(Element) * ir * kNWarps;
        const int target_addr =
            __builtin_amdgcn_readfirstlane(lds_addr_per_wave + lds_offset);
        int offset_v = row_iterator_offset + lane_offset;
        if constexpr (CheckBounds) {
            const int load_row =
                warp_id + (lane_id / kLanesInColumn) * kNWarps +
                ir * kLanesInRow * kNWarps;
            offset_v = load_row < valid_t ? offset_v : -1;
        }
#if defined(__gfx92a__) || defined(__gfx936__) || defined(__gfx938__)
        if constexpr (CheckBounds || !FLA_BV16_INLINE_K_LDS) {
            auto *lds_addr =
                reinterpret_cast<__attribute__((address_space(3))) int *>(
                    static_cast<uintptr_t>(target_addr));
            __builtin_hcu_raw_buffer_load_lds(
                buffer_rsrc, lds_addr, 16, offset_v, 0, 0, 0);
        } else {
            // Full steady K tiles mirror W: no invalid rows, inline direct to
            // LDS, and the consumer-side waitcnt/barrier in the kernel
            // publishes the LDS contents before GEMM1 reads them.
            fla_buffer_load_dwordx4_to_lds_inline(
                buffer_rsrc, target_addr, offset_v);
        }
#else
        (void)buffer_rsrc;
        (void)target_addr;
        (void)offset_v;
#endif
    }
}

template <typename Element, int BT, int BK, int kNWarps>
__device__ __forceinline__ fla_u32x4
fla_read_k_stage_alt(Element *k_lds_base, const int k_stage)
{
    const int warp_id = threadIdx.x / 64;
    const int lane_id = threadIdx.x & 63;
    const int logical_row = k_stage * 16 + lane_id / 4;
    const int logical_col = warp_id * 4 + (lane_id & 3);
    const int partition_id = logical_row / 16 * kNWarps + logical_row % 4;
    const int partition_row = (logical_row % 16) / 4;
    const int wrap_offset = (logical_row & 1) * 4;
    const int in_partition_offset =
        (partition_id * 64 +
         ((partition_row * 16 + logical_col + wrap_offset) % 64)) *
        sizeof(fla_u32x4);
    auto *src_ptr = k_lds_base + in_partition_offset / sizeof(Element);
    return fla_ds_read_m32x16_alt<Element>(src_ptr);
}

template <typename Element, int BT, int BK, int kNWarps>
__device__ __forceinline__ fla_u32x4
fla_read_k_stage_alt_asm(Element *k_lds_base, const int k_stage)
{
    const int warp_id = threadIdx.x / 64;
    const int lane_id = threadIdx.x & 63;
    const int logical_row = k_stage * 16 + lane_id / 4;
    const int logical_col = warp_id * 4 + (lane_id & 3);
    const int partition_id = logical_row / 16 * kNWarps + logical_row % 4;
    const int partition_row = (logical_row % 16) / 4;
    const int wrap_offset = (logical_row & 1) * 4;
    const int in_partition_offset =
        (partition_id * 64 +
         ((partition_row * 16 + logical_col + wrap_offset) % 64)) *
        sizeof(fla_u32x4);
    auto *src_ptr = k_lds_base + in_partition_offset / sizeof(Element);
    return fla_ds_read_m32x16_alt_asm<Element>(src_ptr);
}

// Compact BV128 U/V image: T64 x V128 occupies exactly 16 KiB. Each V8
// stays contiguous; the two-bit XOR serves BOTH the split ds_read_b128
// phases and the consecutive-eight-lane write/matrix-read phases.
__device__ __forceinline__ int fla_uv_index_bv128(const int t, const int v)
{
    const int r = t & 15;
    const int g = (v >> 3) ^ ((r >> 1) & 3);
    const int point = 256 * (t >> 4) + 64 * (r & 3) +
        ((16 * (r >> 2) + g + 4 * (r & 1)) & 63);
    return 8 * point + (v & 7);
}

// Iterations [0,2) and [2,4) overwrite the low/high 8-KiB W halves only
// after their GEMM0 readers have finished. The m0 wrap matches K D2L;
// swizzling the GMEM V8 group creates the compact U image directly.
template <int Begin, int End, typename Element, typename Index,
          bool CheckBounds>
__device__ __forceinline__ void fla_prefetch_u_bv128_to_lds(
    Element *uv_lds, const Element *u_chunk, const Index row_stride,
    const int valid_t)
{
    static_assert(Begin >= 0 && Begin < End && End <= 4);
    static_assert(sizeof(Element) == 2);
    const int wave = threadIdx.x / 64;
    const int lane = threadIdx.x & 63;
    const int base = static_cast<int>(reinterpret_cast<uintptr_t>(uv_lds));
    const fla_i32x4 rsrc = fla_make_uniform_buffer_rsrc(u_chunk);
#pragma unroll
    for (int it = Begin; it < End; ++it) {
        const int t = 16 * it + 4 * (lane >> 4) + wave;
        const int v8 = (lane & 15) ^ ((t >> 1) & 3);
        int offset = static_cast<int>((Index(t) * row_stride + 8 * v8) *
                                      sizeof(Element));
        if constexpr (CheckBounds) {
            offset = t < valid_t ? offset : -1;
        }
        const int target = __builtin_amdgcn_readfirstlane(
            base + 4096 * it + 1024 * wave + ((4 * (wave & 1)) << 16));
        fla_buffer_load_dwordx4_to_lds_inline(rsrc, target, offset);
    }
}

template <typename Element>
__device__ __forceinline__ fla_u32x4 fla_read_u_bv128(
    Element *uv_lds, const int t_stage)
{
    const int lane = threadIdx.x & 63;
    const int t = 16 * t_stage + (lane & 15);
    const int v = 32 * (threadIdx.x / 64) + 8 * (lane >> 4);
    return fla_ds_read_b128(uv_lds + fla_uv_index_bv128(t, v));
}

template <typename Element>
__device__ __forceinline__ void fla_store_v_bv128(
    Element *uv_lds, const int t_stage, const fla_u32x4 packed)
{
#if defined(__gfx938__)
    const int lane = threadIdx.x & 63;
    const int t = 16 * t_stage + (lane & 15);
    const int v = 32 * (threadIdx.x / 64) + 8 * (lane >> 4);
    *reinterpret_cast<fla_u32x4 *>(uv_lds + fla_uv_index_bv128(t, v)) = packed;
#endif
}

template <typename Element>
__device__ __forceinline__ fla_u32x4 fla_read_v_alt_bv128(
    Element *uv_lds, const int t_stage)
{
    const int lane = threadIdx.x & 63;
    const int t = 16 * t_stage + lane / 4;
    const int v = 32 * (threadIdx.x / 64) + 8 * (lane & 3);
    return fla_ds_read_m32x16_alt(uv_lds + fla_uv_index_bv128(t, v));
}

// Four-wave BV64 GEMM1: wave_id selects BV, so every wave iterates over all
// four BK32 blocks.  This is the production K D2L image with the consumer's
// logical_col selected by bk instead of warp_id.
template <typename Element, int BT, int BK, int kNWarps>
__device__ __forceinline__ fla_u32x4
fla_read_k_stage_alt_bv64(Element *k_lds_base, const int bk,
                          const int t_stage)
{
    const int lane_id = threadIdx.x & 63;
    const int logical_row = t_stage * 16 + lane_id / 4;
    const int logical_col = bk * 4 + (lane_id & 3);
    const int partition_id = logical_row / 16 * kNWarps + logical_row % 4;
    const int partition_row = (logical_row % 16) / 4;
    const int wrap_offset = (logical_row & 1) * 4;
    const int in_partition_offset =
        (partition_id * 64 +
         ((partition_row * 16 + logical_col + wrap_offset) % 64)) *
        sizeof(fla_u32x4);
    auto *src_ptr = k_lds_base + in_partition_offset / sizeof(Element);
    return fla_ds_read_m32x16_alt<Element>(src_ptr);
}

template <typename Element, int BT, int BV>
__device__ __forceinline__ fla_u32x4
fla_read_v_stage_m32x16(Element *v_lds_base, const int t_stage)
{
    const int lane_id = threadIdx.x & 63;
    const int lane_m = lane_id & 15;
    const int lane_v_group = lane_id >> 4;
    auto *src_ptr =
        v_lds_base + (t_stage * 16 + lane_m) * BV + lane_v_group * 8;
    return fla_ds_read_m32x16<Element>(src_ptr);
}

template <typename Element, int BT, int BV>
__device__ __forceinline__ fla_u32x4
fla_read_v_stage_m32x16_asm(Element *v_lds_base, const int t_stage)
{
    const int lane_id = threadIdx.x & 63;
    const int lane_m = lane_id & 15;
    const int lane_v_group = lane_id >> 4;
    auto *src_ptr =
        v_lds_base + (t_stage * 16 + lane_m) * BV + lane_v_group * 8;
    return fla_ds_read_m32x16_asm<Element>(src_ptr);
}

// Stage one row-major/V-contiguous T32xV64 U tile directly into LDS.  Within
// each row, producer lane x loads logical V8 group (x XOR row_pair).  The
// physical D2L destination remains the existing m0-wrap image.  Consequently
// every eight-lane D2L write phase keeps eight distinct B128 bank quartets,
// while a q-even consumer can recover a complete V8 without conflicts.
// The targeted forward kernel calls this twice to fill its 8-KiB T64xV64
// W/UV alias.
template <typename Element, typename Index, bool CheckBounds>
__device__ __forceinline__ void
fla_prefetch_u_t32_v64_to_lds(Element *u_lds,
                              const Element *u_gmem,
                              const Index u_row_stride,
                              const int t_base,
                              const int valid_t)
{
    constexpr int kElemsPerPoint = 8;
    constexpr int kAreaPoints = 64;
    constexpr int kAreaBytes =
        kAreaPoints * kElemsPerPoint * int(sizeof(Element));
    constexpr int kOddRowWrapDwordx4 = 4;

    const int warp_id =
        __builtin_amdgcn_readfirstlane(static_cast<int>(threadIdx.x)) >> 6;
    const int lane_id = threadIdx.x & 63;
    const int row_pair = lane_id >> 3;
    const int physical_v_point = lane_id & 7;
    const int t_half = warp_id >> 1;
    const int parity = warp_id & 1;
    const int t_local = t_base + t_half * 16 + row_pair * 2 + parity;
    const int logical_v_point = physical_v_point ^ row_pair;
    const int element_offset =
        static_cast<int>(Index(t_local) * u_row_stride +
                         logical_v_point * kElemsPerPoint);
    int voffset = element_offset * int(sizeof(Element));
    if constexpr (CheckBounds) {
        voffset = t_local < valid_t ? voffset : -1;
    }

    const fla_i32x4 buffer_rsrc = fla_make_uniform_buffer_rsrc(u_gmem);
    const int lds_base = __builtin_amdgcn_readfirstlane(
        static_cast<int>(reinterpret_cast<uintptr_t>(u_lds)));
    const int target_addr =
        lds_base + warp_id * kAreaBytes +
        ((parity * kOddRowWrapDwordx4) << 16);
    fla_buffer_load_dwordx4_to_lds_inline(buffer_rsrc, target_addr, voffset);
}

// Read the contiguous V4 owned by one LIT GEMM0 C lane from the row-XOR U D2L
// image.  q-even lanes own a conflict-free B128/V8 read.  Two full-EXEC
// bpermutes deliver the high V4 to q-odd, so all 64 lanes retain their V4
// residual work.  t_stage is in [0,3]; wave_id owns
// V[16*wave_id:16*wave_id+16].
template <typename Element>
__device__ __forceinline__ fla_u32x2
fla_read_u_v4_d2l_bv64(Element *uv_lds, const int t_stage,
                       const bool region_reuse_barrier)
{
    const int warp_id = threadIdx.x / 64;
    const int lane_id = threadIdx.x & 63;
    const int p = lane_id & 15;
    const int q = lane_id >> 4;
    const int stage32 = t_stage >> 1;
    const int area = 2 * (t_stage & 1) + (p & 1);
    const int row_pair = p >> 1;
    const int v8 = 2 * warp_id + (q >> 1);
    const int physical_v_point = v8 ^ row_pair;
    const int point =
        stage32 * 256 + area * 64 +
        ((row_pair * 8 + physical_v_point + (p & 1) * 4) & 63);

    fla_u32x4 owner_v8 = {0, 0, 0, 0};
    const bool q_even = (q & 1) == 0;
    if (q_even) {
        owner_v8 = fla_ds_read_b128_asm<Element>(uv_lds + point * 8);
    }
    // Pin the DS-read dependency before the lane exchange.  q-odd carries
    // zeros here, but its bpermute source is always the corresponding q-even
    // lane, whose high two dwords are now ready.
    asm volatile("s_waitcnt lgkmcnt(0)\n\t"
                 : "+v"(owner_v8)
                 :
                 : "memory");

    const int owner_lane = lane_id - ((q & 1) << 4);
    uint32_t received_lo =
        fla_ds_bpermute_u32(owner_lane << 2, owner_v8[2]);
    uint32_t received_hi =
        fla_ds_bpermute_u32(owner_lane << 2, owner_v8[3]);
    // The bpermutes are compiler-visible DS intrinsics, so their return-value
    // dependencies supply the required waitcnt without another manual wait.
    // A CTA barrier is needed only when the following V store can reuse LDS
    // still read by another wave.  Keep that barrier compiler-visible as well
    // so independent residual work may overlap the outstanding bpermutes.
    if (region_reuse_barrier) {
        fla_lds_barrier();
    }

    return q_even ? fla_u32x2{owner_v8[0], owner_v8[1]}
                  : fla_u32x2{received_lo, received_hi};
}

// A padded T16xV32 panel has a 40-element row stride and occupies 1280 B.
// Stage 0..2 live in the dead high half of the 16-KiB W/U/V allocation.  Once
// stage 3 has consumed its U region, its output can reuse the beginning of the
// low half.  The four stage regions therefore fit without overwriting any
// future U consumer:
//   stage 3: [0, 2.5 KiB)
//   stage 0: [8, 10.5 KiB), stage 1: [10.5, 13 KiB),
//   stage 2: [13, 15.5 KiB)
__device__ __forceinline__ int fla_v_stage_base_m32x16_bv64(
    const int t_stage)
{
    constexpr int kStageElements = 2 * 16 * 40;
    constexpr int kHighHalfElements = 8 * 1024 / 2;
    constexpr int kAliasElements = 16 * 1024 / 2;
    static_assert(kHighHalfElements + 3 * kStageElements <= kAliasElements,
                  "padded BV64 V stages must fit the W/U/V alias");
    return t_stage == 3 ? 0
                        : kHighHalfElements + t_stage * kStageElements;
}

__device__ __forceinline__ int fla_v_store_lane_offset_m32x16_bv64()
{
    const int warp_id = threadIdx.x / 64;
    const int lane_id = threadIdx.x & 63;
    const int p = lane_id & 15;
    const int q = lane_id >> 4;
    const int g8 = 2 * (warp_id & 1) + (q >> 1);
    const int physical_row = g8 + 4 * (p & 3);
    const int physical_v = 8 * (p >> 2) + 4 * (q & 1);
    return (warp_id >> 1) * (16 * 40) + physical_row * 40 + physical_v;
}

__device__ __forceinline__ int fla_v_read_lane_offset_m32x16_bv64()
{
    const int warp_id = threadIdx.x / 64;
    const int lane_id = threadIdx.x & 63;
    const int p = lane_id & 15;
    const int q = lane_id >> 4;
    return (warp_id >> 1) * (16 * 40) + p * 40 + q * 8;
}

// Store one LIT C V4 into the padded normal matrix-DS image.  The V4 remains
// contiguous, so every lane still issues exactly one ds_write_b64 per stage.
template <typename Element>
__device__ __forceinline__ void
fla_store_v_v4_m32x16_bv64(Element *uv_lds, const int t_stage,
                            const int lane_offset,
                            const fla_f32x4 value)
{
    const fla_u32x2 packed = {
        fla_pack_element_x2_bits<Element>(
            fla_f32x2{value[0], value[1]}),
        fla_pack_element_x2_bits<Element>(
            fla_f32x2{value[2], value[3]}),
    };
    *reinterpret_cast<fla_u32x2 *>(
        uv_lds + fla_v_stage_base_m32x16_bv64(t_stage) + lane_offset) =
        packed;
}

// One normal matrix read covers a T16xV32 panel.  Paired waves read the same
// panel and select its low/high V16 fragment in registers.
template <typename Element>
__device__ __forceinline__ fla_u32x4
fla_read_v_t16_v32_m32x16_bv64(Element *uv_lds, const int t_stage,
                                const int lane_offset)
{
    return fla_ds_read_m32x16<Element>(
        uv_lds + fla_v_stage_base_m32x16_bv64(t_stage) + lane_offset);
}

template <typename Element, int STRIDE>
__device__ __forceinline__ void
fla_store_h_low_pair_kmajor(Element *h_low_base, const int v_local,
                            const int k_col_even, const float h0,
                            const float h1)
{
    const int logical_group8 = k_col_even >> 3;
    const int in_group = k_col_even & 7;
    const int group_swizzle = v_local & 7;
    const int physical_k = ((logical_group8 ^ group_swizzle) << 3) + in_group;
    *reinterpret_cast<uint32_t *>(h_low_base + v_local * STRIDE + physical_k) =
        fla_pack_element_x2_bits<Element>(h0, h1);
}

template <typename Element, int STRIDE>
__device__ __forceinline__ void
fla_store_h_low_pair_kmajor(Element *h_low_base, const int v_local,
                            const int k_col_even, const fla_f32x2 h_pair)
{
    const int logical_group8 = k_col_even >> 3;
    const int in_group = k_col_even & 7;
    const int group_swizzle = v_local & 7;
    const int physical_k = ((logical_group8 ^ group_swizzle) << 3) + in_group;
    *reinterpret_cast<uint32_t *>(h_low_base + v_local * STRIDE + physical_k) =
        fla_pack_element_x2_bits<Element>(h_pair);
}

template <typename Element, int STRIDE>
__device__ __forceinline__ fla_u32x4
fla_read_h_stage_b128_kmajor_bv16(Element *h_low_base,
                                  const int k_stage32)
{
    const int lane_id = threadIdx.x & 63;
    const int lane_v = lane_id & 15;
    const int lane_k_group = lane_id >> 4;
    const int logical_group8 = k_stage32 * 4 + lane_k_group;
    const int group_swizzle = lane_v & 7;
    const int physical_group8 = logical_group8 ^ group_swizzle;
    auto *src_ptr =
        h_low_base + lane_v * STRIDE + physical_group8 * 8;
    return fla_ds_read_b128<Element>(src_ptr);
}

__device__ __forceinline__ int
fla_bv32_v_local_from_state_slot(const int lane_g, const int s)
{
    return lane_g + s * 4;
}

template <typename State>
__device__ __forceinline__ fla_f32x2
load_state_pair(const State *__restrict__ ptr)
{
    return fla_f32x2{
        ck_tile::type_convert<float>(ptr[0]),
        ck_tile::type_convert<float>(ptr[1])};
}

template <typename State>
__device__ __forceinline__ void
store_state_pair(State *__restrict__ ptr, const fla_f32x2 value)
{
    // Scalar stores are intentional: an envelope slot pitch is not required
    // to preserve float2/bf16x2 alignment across slots.
    ptr[0] = ck_tile::type_convert<State>(value[0]);
    ptr[1] = ck_tile::type_convert<State>(value[1]);
}

template <typename Kernel_traits, typename Params>
__device__ __forceinline__ void
store_final_state_bv16(
    const Params &params,
    const int v_begin,
    typename Kernel_traits::State *__restrict__ ht_ptr,
    const fla_f32x2 (&state_reg)[4])
{
    using index_t = typename Kernel_traits::index_t;

    const int tid = threadIdx.x;
    const int warp_id = tid / 64;
    const int lane_id = tid & 63;
    const int lane_m = lane_id & 15;
    const int lane_k_group = lane_id >> 4;
    const int k0 = warp_id * 32 + lane_m * 2;

#pragma unroll
    for (int s = 0; s < 4; ++s) {
        const int v_local = lane_k_group + s * 4;
        const int v_col = v_begin + v_local;
        if (v_col < params.V) {
            store_state_pair(
                ht_ptr + index_t(v_col) * params.K + k0, state_reg[s]);
        }
    }
}

template <typename Kernel_traits, typename Params>
__device__ __forceinline__ void
store_final_state_bv32(
    const Params &params,
    const int v_begin,
    typename Kernel_traits::State *__restrict__ ht_ptr,
    const fla_f32x2 (&state_reg)[8])
{
    using index_t = typename Kernel_traits::index_t;

    const int tid = threadIdx.x;
    const int warp_id = tid / 64;
    const int lane_id = tid & 63;
    const int lane_m = lane_id & 15;
    const int lane_g = lane_id >> 4;
    const int k0 = warp_id * 32 + lane_m * 2;

#pragma unroll
    for (int s = 0; s < 8; ++s) {
        const int v_local =
            fla_bv32_v_local_from_state_slot(lane_g, s);
        const int v_col = v_begin + v_local;
        if (v_col < params.V) {
            store_state_pair(
                ht_ptr + index_t(v_col) * params.K + k0, state_reg[s]);
        }
    }
}

// BV32 h_low swizzle: logical (v, k0-even) -> physical element offset.
// Paired with fla_store_h_low_pair_swizzled_bv32,
// fla_read_h_stage_b128_swizzled_bv32, and
// fla_store_h_snapshot_swizzled_bv32 for bank-conflict-free MMAC access.
__device__ __forceinline__ int fla_h_low_swizzle_elem_bv32(const int v,
                                                           const int k0)
{
    const int warp_of_k = k0 >> 5;
    const int k_dword = (k0 & 31) >> 1;
    const int in_slot = 4 * (v & 1) + (k_dword >> 2);
    const int in_slot_sw = in_slot ^ ((v >> 1) & 7);
    const int phys_dword =
        warp_of_k * 512 + (v >> 1) * 32 + in_slot_sw * 4 + (k_dword & 3);
    return phys_dword * 2;
}

template <typename Element>
__device__ __forceinline__ void
fla_store_h_low_pair_swizzled_bv32(Element *h_low_base, const int v_local,
                                   const int k0, const fla_f32x2 h_pair)
{
    const int elem = fla_h_low_swizzle_elem_bv32(v_local, k0);
    const uint32_t pk = fla_pack_element_x2_bits<Element>(h_pair);
    fla_ds_write_b32_at<Element>(h_low_base, elem, pk);
}

// Pack state_reg into k_low_pk[0..7] and issue one ds_write_b32 per slot.
template <typename Element>
__device__ __forceinline__ void
fla_store_h_low_state_reg_swizzled_bv32(
    Element *h_low_base, const int lane_g, const int k0,
    const fla_f32x2 (&state_reg)[8])
{
#pragma unroll
    for (int pattern_id = 0; pattern_id < 8; ++pattern_id) {
        const int v_local = lane_g + pattern_id * 4;
        const uint32_t pk =
            fla_pack_element_x2_bits<Element>(state_reg[pattern_id]);
        const int elem = fla_h_low_swizzle_elem_bv32(v_local, k0);
        fla_ds_write_b32_at<Element>(h_low_base, elem, pk);
    }
}

template <typename Element>
__device__ __forceinline__ fla_u32x4
fla_read_h_stage_b128_swizzled_bv32(Element *h_low_base, const int k_stage,
                                    const int v_n)
{
    const int lane_id = threadIdx.x & 63;
    const int lane_m = lane_id & 15;
    const int lane_g = lane_id >> 4;
    const int v = lane_m * 2 + v_n;
    const int k_base = lane_g * 8 + k_stage * 32;
    return fla_ds_read_b128<Element>(
        h_low_base + fla_h_low_swizzle_elem_bv32(v, k_base));
}

template <typename Element, typename Params, typename Index, int BV, int BK,
          int kThreads>
__device__ __forceinline__ void fla_store_h_snapshot_swizzled_bv32(
    const Params &params, const int chunk, const int v_begin,
    const Element *__restrict__ h_low_base, Element *__restrict__ h_ptr,
    const int tid)
{
#pragma unroll
    for (int vec_idx = tid; vec_idx < (BV * BK) / 8; vec_idx += kThreads) {
        const int v_local = vec_idx / (BK / 8);
        const int k_vec = (vec_idx - v_local * (BK / 8)) * 8;
        const int v_col = v_begin + v_local;
        const fla_u32x4 h_pack = *reinterpret_cast<const fla_u32x4 *>(
            h_low_base + fla_h_low_swizzle_elem_bv32(v_local, k_vec));
        const int32_t h_off = static_cast<int32_t>(
            (Index(chunk) * params.h_chunk_stride + Index(v_col) * params.K +
             k_vec) *
            sizeof(Element));
        fla_buffer_store_vgpr<4>(
            h_ptr, v_col < params.V ? h_off : -1, h_pack);
    }
}

// w_tensor_elems is unused: OOB is now expressed via the hardware descriptor
// (voffset=-1), matching every other buffer_load/store call in the kernel,
// instead of the CK software-predicated bound check this used to route
// through.  The parameter is kept so existing call sites do not need to
// recompute/drop it.
template <typename Element, typename Index, int BK>
__device__ __forceinline__ fla_u32x4
fla_load_w_stage_bv32_vgpr(const Element *__restrict__ w_ptr,
                           const Index t_begin, const int k_stage,
                           const Index w_row_stride, const bool valid_row,
                           const Index w_tensor_elems)
{
    (void)w_tensor_elems;
    const int warp_id = threadIdx.x / 64;
    const int lane_id = threadIdx.x & 63;
    const int lane_m = lane_id & 15;
    const int lane_g = lane_id >> 4;
    const Index t_row = Index(t_begin) + Index(warp_id * 16 + lane_m);
    const Index k_col = Index(lane_g * 8 + k_stage * 32);
    const Index element_offset = t_row * w_row_stride + k_col;
    const int32_t voffset =
        valid_row ? static_cast<int32_t>(element_offset * sizeof(Element))
                  : -1;
    return fla_buffer_load_element_v8_vgpr<Element>(w_ptr, voffset);
}

template <typename Element, typename Index, int BK>
__device__ __forceinline__ void
fla_load_w_tile_bv32_vgpr(const Element *__restrict__ w_ptr,
                          const Index t_begin, const Index w_row_stride,
                          const bool valid_row, const Index w_tensor_elems,
                          fla_u32x4 (&w_pack)[4])
{
#pragma unroll
    for (int k_stage = 0; k_stage < 4; ++k_stage) {
        w_pack[k_stage] =
            fla_load_w_stage_bv32_vgpr<Element, Index, BK>(
                w_ptr, t_begin, k_stage, w_row_stride, valid_row,
                w_tensor_elems);
    }
}

template <typename Element>
__device__ __forceinline__ void
fla_store_v_tile_m32x16_bv32_swizzled(Element *tile_base, const int t_local,
                                        const fla_f32x4 lo, const fla_f32x4 hi,
                                        const int lane_g)
{
    fla_store_v_tile_m32x16_v8_swizzled<Element, 32>(
        tile_base, t_local, lo, hi, lane_g);
}

}  // namespace FLA_NAMESPACE
