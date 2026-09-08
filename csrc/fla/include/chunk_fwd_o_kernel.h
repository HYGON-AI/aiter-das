// SPDX-License-Identifier: MIT
#pragma once

#include "chunk_fwd_o.h"
#include "utils.h"

namespace FLA_NAMESPACE {

template <typename Element>
__device__ __forceinline__ float elem_to_float(const Element x)
{
    return ck_tile::type_convert<float>(x);
}

template <typename Element>
__device__ __forceinline__ Element float_to_elem(const float x)
{
    return ck_tile::type_convert<Element>(x);
}

template <bool UseExp2>
__device__ __forceinline__ float gate_exp(const float x)
{
    return fla_exp<false, UseExp2>(x);
}

template <bool UseExp2, bool UseSafeExp>
__device__ __forceinline__ float gate_delta_exp(const float x)
{
    return fla_exp<UseSafeExp, UseExp2>(x);
}

template <int Row>
__device__ __forceinline__ fla_f32x4
pick_interleaved_v4(const fla_f32x4 v0, const fla_f32x4 v1,
                    const fla_f32x4 v2, const fla_f32x4 v3)
{
    return fla_f32x4{v0[Row], v1[Row], v2[Row], v3[Row]};
}

template <int Row>
__device__ __forceinline__ fla_f32x4
pick_v_stage16_v4(const fla_f32x4 v0, const fla_f32x4 v1,
                  const fla_f32x4 v2, const fla_f32x4 v3)
{
    if constexpr (Row == 0) {
        return fla_f32x4{v0[0], v1[0], v0[1], v1[1]};
    } else if constexpr (Row == 1) {
        return fla_f32x4{v0[2], v1[2], v0[3], v1[3]};
    } else if constexpr (Row == 2) {
        return fla_f32x4{v2[0], v3[0], v2[1], v3[1]};
    } else {
        return fla_f32x4{v2[2], v3[2], v2[3], v3[3]};
    }
}

template <typename Element, int STRIDE>
__device__ __forceinline__ fla_f32x4
mmac_q_rhs128(Element *q_lds_tile, Element *rhs_low_tile)
{
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;

    fla_f32x4 acc = {0.0f, 0.0f, 0.0f, 0.0f};
    fla_u32x4 q_pack =
        fla_read_w_stage<Element, 64, 128, 4>(q_lds_tile, 0);
    fla_u32x4 rhs_pack =
        fla_read_h_stage_b128_kmajor_bv16<Element, STRIDE>(rhs_low_tile, 0);

#pragma unroll
    for (int k_stage = 0; k_stage < 4; ++k_stage) {
        fla_u32x4 q_next = {0, 0, 0, 0};
        fla_u32x4 rhs_next = {0, 0, 0, 0};
        if (k_stage != 3) {
            q_next =
                fla_read_w_stage<Element, 64, 128, 4>(q_lds_tile, k_stage + 1);
            rhs_next =
                fla_read_h_stage_b128_kmajor_bv16<Element, STRIDE>(
                    rhs_low_tile, k_stage + 1);
        }

        ElementVec4 a = fla_vec4_from_pack<Element>(q_pack, 0);
        ElementVec4 b = fla_vec4_from_pack<Element>(rhs_pack, 0);
        acc = fla_mmac_f32_16x16x16<Element>(a, b, acc);

        a = fla_vec4_from_pack<Element>(q_pack, 4);
        b = fla_vec4_from_pack<Element>(rhs_pack, 4);
        acc = fla_mmac_f32_16x16x16<Element>(a, b, acc);

        q_pack = q_next;
        rhs_pack = rhs_next;
    }

    return acc;
}

template <typename Element, int STRIDE>
__device__ __forceinline__ fla_f32x4
mmac_a_rhs16(const typename fla_dtype_traits<Element>::vec4_t a_vec,
             Element *rhs_low_tile, fla_f32x4 acc)
{
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;
    const fla_u32x4 rhs_pack =
        fla_read_h_stage_b128_kmajor_bv16<Element, STRIDE>(rhs_low_tile, 0);
    const ElementVec4 b_vec = fla_vec4_from_pack<Element>(rhs_pack, 0);
    return fla_mmac_f32_16x16x16<Element>(a_vec, b_vec, acc);
}

template <typename Element>
__device__ __forceinline__ void
store_final_v4(Element *__restrict__ o, const ChunkFwdOParams::index_t o_row,
               const int v_col_base, const fla_f32x4 state_v4,
               const fla_f32x4 av_v4, const bool valid_row,
               const int v_limit, const float state_scale,
               const float av_scale)
{
#pragma unroll
    for (int j = 0; j < 4; ++j) {
        const int vc = v_col_base + j;
        if (valid_row && vc < v_limit) {
            const float out_value = state_v4[j] * state_scale + av_v4[j] * av_scale;
            o[o_row + vc] = float_to_elem<Element>(out_value);
        }
    }
}

template <typename Element>
__device__ __forceinline__ void
store_final_v4_no_oob(Element *__restrict__ o,
                      const ChunkFwdOParams::index_t o_row,
                      const int v_col_base, const fla_f32x4 state_v4,
                      const fla_f32x4 av_v4, const float state_scale,
                      const float av_scale)
{
    const fla_f32x2 lo = {
        state_v4[0] * state_scale + av_v4[0] * av_scale,
        state_v4[1] * state_scale + av_v4[1] * av_scale};
    const fla_f32x2 hi = {
        state_v4[2] * state_scale + av_v4[2] * av_scale,
        state_v4[3] * state_scale + av_v4[3] * av_scale};
    const int32_t offset_bytes =
        static_cast<int32_t>((o_row + v_col_base) * sizeof(Element));
    fla_buffer_store_v4_vector_no_oob<Element>(o, offset_bytes, lo, hi);
}

template <typename Element>
__device__ __forceinline__ void
store_scaled_v4_no_oob(Element *__restrict__ o,
                       const ChunkFwdOParams::index_t o_row,
                       const int v_col_base, const fla_f32x4 out_v4)
{
    const fla_f32x2 lo = {out_v4[0], out_v4[1]};
    const fla_f32x2 hi = {out_v4[2], out_v4[3]};
    const int32_t offset_bytes =
        static_cast<int32_t>((o_row + v_col_base) * sizeof(Element));
    fla_buffer_store_v4_vector_no_oob<Element>(o, offset_bytes, lo, hi);
}

template <typename Element>
__device__ __forceinline__ void
store_packed_v8_no_oob(Element *__restrict__ o,
                       const ChunkFwdOParams::index_t o_row,
                       const int v_col_base, const fla_u32x4 packed_v8)
{
    const int32_t offset_bytes =
        static_cast<int32_t>((o_row + v_col_base) * sizeof(Element));
    fla_buffer_store_dwordx4_vgpr(o, offset_bytes, packed_v8);
}

__device__ __forceinline__ fla_f32x4
combine_o_av_native(const fla_f32x4 o_v4, const fla_f32x4 av_v4,
                    const float state_scale, const float av_scale)
{
    return fla_f32x4{
        o_v4[0] * state_scale + av_v4[0] * av_scale,
        o_v4[1] * state_scale + av_v4[1] * av_scale,
        o_v4[2] * state_scale + av_v4[2] * av_scale,
        o_v4[3] * state_scale + av_v4[3] * av_scale};
}

template <typename Element>
__device__ __forceinline__ uint32_t
combine_o_av_pair_packed(const float o0, const float o1, const float av0,
                         const float av1, const float state_scale,
                         const float av_scale)
{
    const fla_f32x2 o_pair = {o0, o1};
    const fla_f32x2 av_pair = {av0, av1};
    const fla_f32x2 state_scale_pair = {state_scale, state_scale};
    const fla_f32x2 av_scale_pair = {av_scale, av_scale};
    const fla_f32x2 av_scaled = fla_pk_mul_f32(av_pair, av_scale_pair);
    const fla_f32x2 out =
        fla_pk_fma_f32(o_pair, state_scale_pair, av_scaled);
    return fla_pack_element_x2_bits<Element>(out);
}

__device__ __forceinline__ void
wait_lgkmcnt0_dep(fla_f32x4 &dep0, fla_f32x4 &dep1, fla_f32x4 &dep2,
                  fla_f32x4 &dep3)
{
    asm volatile("s_waitcnt lgkmcnt(0)\n\t"
                 : "+v"(dep0), "+v"(dep1), "+v"(dep2), "+v"(dep3)
                 :
                 : "memory");
}

template <int SrcAcc, int SrcElem>
__device__ __forceinline__ float
fetch_av_from_lane_group(const fla_f32x4 (&c_av)[4], const int src_group)
{
    const int lane_m = (threadIdx.x & 63) & 15;
    const int src_lane = lane_m + src_group * 16;
    const uint32_t bits = ck_tile::bit_cast<uint32_t>(c_av[SrcAcc][SrcElem]);
    return ck_tile::bit_cast<float>(
        fla_ds_bpermute_u32(src_lane << 2, bits));
}

template <int DstAcc>
__device__ __forceinline__ fla_f32x4
remap_av_native_to_o_layout(const fla_f32x4 (&c_av)[4],
                            const int lane_group)
{
    const int src_group = (lane_group & 1) * 2 + (DstAcc >> 1);
    fla_f32x4 even = {};
    fla_f32x4 odd = {};
    if constexpr ((DstAcc & 1) == 0) {
        even = fla_f32x4{
            fetch_av_from_lane_group<0, 0>(c_av, src_group),
            fetch_av_from_lane_group<0, 2>(c_av, src_group),
            fetch_av_from_lane_group<2, 0>(c_av, src_group),
            fetch_av_from_lane_group<2, 2>(c_av, src_group)};
        odd = fla_f32x4{
            fetch_av_from_lane_group<0, 1>(c_av, src_group),
            fetch_av_from_lane_group<0, 3>(c_av, src_group),
            fetch_av_from_lane_group<2, 1>(c_av, src_group),
            fetch_av_from_lane_group<2, 3>(c_av, src_group)};
    } else {
        even = fla_f32x4{
            fetch_av_from_lane_group<1, 0>(c_av, src_group),
            fetch_av_from_lane_group<1, 2>(c_av, src_group),
            fetch_av_from_lane_group<3, 0>(c_av, src_group),
            fetch_av_from_lane_group<3, 2>(c_av, src_group)};
        odd = fla_f32x4{
            fetch_av_from_lane_group<1, 1>(c_av, src_group),
            fetch_av_from_lane_group<1, 3>(c_av, src_group),
            fetch_av_from_lane_group<3, 1>(c_av, src_group),
            fetch_av_from_lane_group<3, 3>(c_av, src_group)};
    }
    return (lane_group >> 1) == 0 ? even : odd;
}

template <int Acc, int Elem>
__device__ __forceinline__ float
fetch_c_from_lane_group(const fla_f32x4 (&c)[4], const int src_group)
{
    const int lane_m = (threadIdx.x & 63) & 15;
    const int src_lane = lane_m + src_group * 16;
    const uint32_t bits = ck_tile::bit_cast<uint32_t>(c[Acc][Elem]);
    return ck_tile::bit_cast<float>(
        fla_ds_bpermute_u32(src_lane << 2, bits));
}

template <int SCol>
__device__ __forceinline__ float
fetch_a_parity_col(const fla_f32x4 (&c_A)[4])
{
    constexpr int acc = ((SCol >> 5) << 1) + (SCol & 1);
    constexpr int half_col = (SCol & 31) >> 1;
    constexpr int elem = half_col >> 2;
    constexpr int src_group = half_col & 3;
    return fetch_c_from_lane_group<acc, elem>(c_A, src_group);
}

template <int SBlock, int J>
__device__ __forceinline__ float
fetch_a_parity_stage_value(const fla_f32x4 (&c_A)[4],
                           const int lane_group)
{
    constexpr int s0 = SBlock * 16 + J;
    constexpr int s1 = SBlock * 16 + 4 + J;
    constexpr int s2 = SBlock * 16 + 8 + J;
    constexpr int s3 = SBlock * 16 + 12 + J;
    const float v0 = fetch_a_parity_col<s0>(c_A);
    const float v1 = fetch_a_parity_col<s1>(c_A);
    const float v2 = fetch_a_parity_col<s2>(c_A);
    const float v3 = fetch_a_parity_col<s3>(c_A);
    float out = v0;
    out = lane_group == 1 ? v1 : out;
    out = lane_group == 2 ? v2 : out;
    out = lane_group == 3 ? v3 : out;
    return out;
}

template <typename Element, bool FullChunk>
__device__ __forceinline__ fla_u32x4
load_q_reg_stage(const Element *__restrict__ q,
                 const ChunkFwdOParams::index_t q_tile_base,
                 const ChunkFwdOParams::index_t q_row_stride,
                 const int k_stage32, const int valid_t)
{
    const int warp_id = threadIdx.x >> 6;
    const int lane_id = threadIdx.x & 63;
    const int lane_m = lane_id & 15;
    const int lane_k_group = lane_id >> 4;
    const int row = warp_id * 16 + lane_m;
    const int k_point = k_stage32 * 4 + lane_k_group;
    const fla_buffer_accessor buffer(q + q_tile_base);
    const int32_t element_offset =
        static_cast<int32_t>(ChunkFwdOParams::index_t(row) * q_row_stride +
                             k_point * 8);
    int32_t offset_bytes = 0;
    if constexpr (FullChunk) {
        offset_bytes = element_offset * static_cast<int32_t>(sizeof(Element));
    } else {
        offset_bytes = row < valid_t
            ? element_offset * static_cast<int32_t>(sizeof(Element))
            : -1;
    }
    return fla_buffer_load_dwordx4_vgpr_inline(buffer.buffer_res,
                                               offset_bytes);
}

template <typename Element>
__device__ __forceinline__ void
prefetch_h_stage64_to_lds_doc(Element *__restrict__ rhs_lds,
                              const Element *__restrict__ h_gmem,
                              const int k_stage64)
{
    constexpr int kStageK = 64;
    constexpr int kHVStride = 128;
    constexpr int kElemsPerPoint = 8;
    constexpr int kStageKPoints = kStageK / kElemsPerPoint;
    constexpr int kSlotsPerArea = 64;
    constexpr int kNWarps = 4;
    constexpr int kStagePoints = kStageKPoints * 64;
    constexpr int kStageBytes =
        kStagePoints * kElemsPerPoint * int(sizeof(Element));
    constexpr int kAreaBytes =
        kSlotsPerArea * kElemsPerPoint * int(sizeof(Element));

    const int lane_id = threadIdx.x & 63;
    const int warp_id = __builtin_amdgcn_readfirstlane(threadIdx.x) >> 6;
    const int lds_base = __builtin_amdgcn_readfirstlane(
        static_cast<int>(reinterpret_cast<uintptr_t>(rhs_lds)));
    const int lane_v_slot = lane_id >> 3;
    const int k_point = lane_id & 7;
    const fla_buffer_accessor buffer(h_gmem);

#pragma unroll
    for (int area_iter = 0; area_iter < 2; ++area_iter) {
        const int area = warp_id + area_iter * kNWarps;
        const int block16 = lane_v_slot >> 1;
        const int in_pair = lane_v_slot & 1;
        const int v = block16 * 16 + area * 2 + in_pair;
        const int element_offset =
            int(v * kHVStride +
                k_stage64 * kStageK + k_point * kElemsPerPoint);
        const int offset_v = element_offset * int(sizeof(Element));
        const int target_addr =
            lds_base + k_stage64 * kStageBytes + area * kAreaBytes +
            (area << 16);
        fla_buffer_load_dwordx4_to_lds_inline(
            buffer.buffer_res, target_addr, offset_v);
    }
}

template <typename Element>
__device__ __forceinline__ void
prefetch_k_stage64_to_lds_doc(Element *__restrict__ rhs_lds,
                              const Element *__restrict__ k_gmem,
                              const ChunkFwdOParams::index_t k_t_stride,
                              const int k_stage64, const int valid_t)
{
    constexpr int kStageK = 64;
    constexpr int kElemsPerPoint = 8;
    constexpr int kStageKPoints = kStageK / kElemsPerPoint;
    constexpr int kSlotsPerArea = 64;
    constexpr int kNWarps = 4;
    constexpr int kStagePoints = kStageKPoints * 64;
    constexpr int kStageBytes =
        kStagePoints * kElemsPerPoint * int(sizeof(Element));
    constexpr int kAreaBytes =
        kSlotsPerArea * kElemsPerPoint * int(sizeof(Element));

    const int lane_id = threadIdx.x & 63;
    const int warp_id = __builtin_amdgcn_readfirstlane(threadIdx.x) >> 6;
    const int lds_base = __builtin_amdgcn_readfirstlane(
        static_cast<int>(reinterpret_cast<uintptr_t>(rhs_lds)));
    const int lane_t_slot = lane_id >> 3;
    const int k_point = lane_id & 7;
    const fla_buffer_accessor buffer(k_gmem);

#pragma unroll
    for (int area_iter = 0; area_iter < 2; ++area_iter) {
        const int area = warp_id + area_iter * kNWarps;
        const int t_local =
            (lane_t_slot >> 2) * 32 + area * 4 + (lane_t_slot & 3);
        const int element_offset =
            int(ChunkFwdOParams::index_t(t_local) * k_t_stride +
                k_stage64 * kStageK + k_point * kElemsPerPoint);
        const int offset_v =
            t_local < valid_t ? element_offset * int(sizeof(Element)) : -1;
        const int target_addr =
            lds_base + k_stage64 * kStageBytes + area * kAreaBytes +
            (area << 16);
        fla_buffer_load_dwordx4_to_lds_inline(
            buffer.buffer_res, target_addr, offset_v);
    }
}

__device__ __forceinline__ int k_move_slot_from_tn_kpoint(const int t_n,
                                                          const int k_point);

template <typename Element, bool FullChunk>
__device__ __forceinline__ fla_u32x4
load_k_stage64_area_to_vgpr_doc(
    const Element *__restrict__ k_gmem,
    const ChunkFwdOParams::index_t k_t_stride,
    const int k_stage64, const int valid_t, const int area_iter)
{
    constexpr int kStageK = 64;
    constexpr int kElemsPerPoint = 8;
    constexpr int kNWarps = 4;

    const int lane_id = threadIdx.x & 63;
    const int warp_id = __builtin_amdgcn_readfirstlane(threadIdx.x) >> 6;
    const int lane_t_slot = lane_id >> 3;
    const int k_point = lane_id & 7;
    const int area = warp_id + area_iter * kNWarps;
    const int t_local =
        (lane_t_slot >> 2) * 32 + area * 4 + (lane_t_slot & 3);
    const int element_offset =
        int(ChunkFwdOParams::index_t(t_local) * k_t_stride +
            k_stage64 * kStageK + k_point * kElemsPerPoint);
    int offset_v = 0;
    if constexpr (FullChunk) {
        offset_v = element_offset * int(sizeof(Element));
    } else {
        offset_v = t_local < valid_t ? element_offset * int(sizeof(Element)) : -1;
    }
    const fla_buffer_accessor buffer(k_gmem);
    return fla_buffer_load_dwordx4_vgpr_inline(buffer.buffer_res, offset_v);
}

template <typename Element>
__device__ __forceinline__ void
write_k_stage64_area_from_vgpr_doc(Element *__restrict__ rhs_lds,
                                   const fla_u32x4 data,
                                   const int k_stage64,
                                   const int area_iter)
{
    constexpr int kStageK = 64;
    constexpr int kElemsPerPoint = 8;
    constexpr int kStageKPoints = kStageK / kElemsPerPoint;
    constexpr int kSlotsPerArea = 64;
    constexpr int kNWarps = 4;
    constexpr int kStagePoints = kStageKPoints * 64;

    const int lane_id = threadIdx.x & 63;
    const int warp_id = __builtin_amdgcn_readfirstlane(threadIdx.x) >> 6;
    const int lane_t_slot = lane_id >> 3;
    const int k_point = lane_id & 7;
    const int area = warp_id + area_iter * kNWarps;
    const int t_local =
        (lane_t_slot >> 2) * 32 + area * 4 + (lane_t_slot & 3);
    const int producer_lane = k_move_slot_from_tn_kpoint(t_local, k_point);
    const int wrapped_slot = (producer_lane + area) & (kSlotsPerArea - 1);
    const int lds_point =
        k_stage64 * kStagePoints + area * kSlotsPerArea + wrapped_slot;
    *reinterpret_cast<fla_u32x4 *>(rhs_lds + lds_point * kElemsPerPoint) =
        data;
}

__device__ __forceinline__ int h_move_area_from_v(const int v)
{
    return (v & 15) >> 1;
}

__device__ __forceinline__ int h_move_slot_from_v_kpoint(const int v,
                                                         const int k_point)
{
    return (((v >> 4) << 1) + (v & 1)) * 8 + k_point;
}

__device__ __forceinline__ int k_move_area_from_tn(const int t_n)
{
    return (t_n & 31) >> 2;
}

__device__ __forceinline__ int k_move_slot_from_tn_kpoint(const int t_n,
                                                          const int k_point)
{
    return (((t_n >> 5) << 2) + (t_n & 3)) * 8 + k_point;
}

template <typename Element>
__device__ __forceinline__ fla_u32x4
read_h_stage32_doc(Element *__restrict__ rhs_lds,
                   const int k_stage32, const int acc_id)
{
    constexpr int kStageK = 64;
    constexpr int kElemsPerPoint = 8;
    constexpr int kStageKPoints = kStageK / kElemsPerPoint;
    constexpr int kSlotsPerArea = 64;
    constexpr int kStagePoints = kStageKPoints * 64;

    const int lane_id = threadIdx.x & 63;
    const int lane_n = lane_id & 15;
    const int lane_k_group = lane_id >> 4;
    const int v_half = acc_id >> 1;
    const int v_parity = acc_id & 1;
    const int v = v_half * 32 + lane_n * 2 + v_parity;
    const int logical_group8 = k_stage32 * 4 + lane_k_group;
    const int k_stage64 = logical_group8 >> 3;
    const int k_point = logical_group8 & 7;
    const int area = h_move_area_from_v(v);
    const int producer_lane = h_move_slot_from_v_kpoint(v, k_point);
    const int wrapped_slot = (producer_lane + area) & (kSlotsPerArea - 1);
    const int lds_point =
        k_stage64 * kStagePoints + area * kSlotsPerArea + wrapped_slot;
    return fla_ds_read_b128_asm<Element>(rhs_lds + lds_point * kElemsPerPoint);
}

template <typename Element>
__device__ __forceinline__ fla_u32x4
read_k_stage32_doc(Element *__restrict__ rhs_lds,
                   const int k_stage32, const int acc_id)
{
    constexpr int kStageK = 64;
    constexpr int kElemsPerPoint = 8;
    constexpr int kStageKPoints = kStageK / kElemsPerPoint;
    constexpr int kSlotsPerArea = 64;
    constexpr int kStagePoints = kStageKPoints * 64;

    const int lane_id = threadIdx.x & 63;
    const int lane_n = lane_id & 15;
    const int lane_k_group = lane_id >> 4;
    const int t_n = lane_n * 4 + acc_id;
    const int logical_group8 = k_stage32 * 4 + lane_k_group;
    const int k_stage64 = logical_group8 >> 3;
    const int k_point = logical_group8 & 7;
    const int area = k_move_area_from_tn(t_n);
    const int producer_lane = k_move_slot_from_tn_kpoint(t_n, k_point);
    const int wrapped_slot = (producer_lane + area) & (kSlotsPerArea - 1);
    const int lds_point =
        k_stage64 * kStagePoints + area * kSlotsPerArea + wrapped_slot;
    return fla_ds_read_b128_asm<Element>(rhs_lds + lds_point * kElemsPerPoint);
}

template <typename Element, bool FullChunk>
__device__ __forceinline__ void
prefetch_v_stage32_to_lds_doc(Element *__restrict__ v_lds,
                          const Element *__restrict__ v_gmem,
                          const ChunkFwdOParams::index_t v_row_stride,
                          const int s_base, const int valid_t)
{
    constexpr int BV = 64;
    constexpr int kElemsPerPoint = 8;
    constexpr int kAreaPoints = BV;
    constexpr int kOddRowWrapDwordx4 = 4;
    constexpr int kAreaBytes =
        kAreaPoints * kElemsPerPoint * int(sizeof(Element));

    const int warp_id = __builtin_amdgcn_readfirstlane(threadIdx.x) >> 6;
    const int lane_id = threadIdx.x & 63;
    const int row_pair = lane_id >> 3;
    const int v_point = lane_id & 7;
    const int area = warp_id;
    const int t_half = area >> 1;
    const int t_parity = area & 1;
    const fla_buffer_accessor buffer(v_gmem);
    const int lds_base = __builtin_amdgcn_readfirstlane(
        static_cast<int>(reinterpret_cast<uintptr_t>(v_lds)));

    const int t_local = s_base + t_half * 16 + row_pair * 2 + t_parity;
    const int element_offset =
        int(ChunkFwdOParams::index_t(t_local) * v_row_stride +
            v_point * kElemsPerPoint);
    int offset_v = 0;
    if constexpr (FullChunk) {
        offset_v = element_offset * int(sizeof(Element));
    } else {
        offset_v = t_local < valid_t ? element_offset * int(sizeof(Element)) : -1;
    }
    const int target_addr =
        lds_base + area * kAreaBytes +
        ((t_parity * kOddRowWrapDwordx4) << 16);
    fla_buffer_load_dwordx4_to_lds_inline(
        buffer.buffer_res, target_addr, offset_v);
}

template <typename Element>
__device__ __forceinline__ fla_u32x4
read_v_stage32_nmajor_alt_doc(Element *__restrict__ v_lds,
                              const int t_half, const int n_pair)
{
    constexpr int kElemsPerPoint = 8;
    constexpr int kPointsPerRow = 8;
    constexpr int kAreaPoints = 64;
    constexpr int kOddRowWrapDwordx4 = 4;

    const int lane_id = threadIdx.x & 63;
    const int logical_t = lane_id >> 2;
    const int v_group4 = lane_id & 3;
    const int v_point = n_pair * 4 + v_group4;
    const int row_pair = logical_t >> 1;
    const int parity = logical_t & 1;
    const int area = t_half * 2 + parity;

    const int physical_point =
        area * kAreaPoints +
        ((row_pair * kPointsPerRow + v_point +
          parity * kOddRowWrapDwordx4) &
         (kAreaPoints - 1));

    return fla_ds_read_m32x16_alt_asm<Element>(
        v_lds + physical_point * kElemsPerPoint);
}

template <typename Element>
__device__ __forceinline__ void
mmac_qpack_rhs_pack(const fla_u32x4 q_pack, const fla_u32x4 rhs_pack,
                    fla_f32x4 &acc)
{
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;

    ElementVec4 a = fla_vec4_from_pack<Element>(q_pack, 0);
    ElementVec4 b = fla_vec4_from_pack<Element>(rhs_pack, 0);
    fla_mmac_f32_16x16x16_accumulate<Element>(a, b, acc);

    a = fla_vec4_from_pack<Element>(q_pack, 4);
    b = fla_vec4_from_pack<Element>(rhs_pack, 4);
    fla_mmac_f32_16x16x16_accumulate<Element>(a, b, acc);
}

template <typename Element>
__device__ __forceinline__ void
mmac_qreg_h64_doc(const fla_u32x4 (&q_reg)[4],
                  Element *__restrict__ rhs_lds,
                  const int k_stage64, fla_f32x4 (&acc)[4])
{
    const int k_stage32_lo = k_stage64 * 2;
    const int k_stage32_hi = k_stage32_lo + 1;
    const fla_u32x4 q_pack_lo = q_reg[k_stage32_lo];
    const fla_u32x4 q_pack_hi = q_reg[k_stage32_hi];

    fla_u32x4 rhs_lo0 =
        read_h_stage32_doc<Element>(rhs_lds, k_stage32_lo, 0);
    fla_u32x4 rhs_lo1 =
        read_h_stage32_doc<Element>(rhs_lds, k_stage32_lo, 1);
    fla_u32x4 rhs_lo2 =
        read_h_stage32_doc<Element>(rhs_lds, k_stage32_lo, 2);
    fla_u32x4 rhs_lo3 =
        read_h_stage32_doc<Element>(rhs_lds, k_stage32_lo, 3);
    fla_u32x4 rhs_hi0 =
        read_h_stage32_doc<Element>(rhs_lds, k_stage32_hi, 0);
    fla_u32x4 rhs_hi1 =
        read_h_stage32_doc<Element>(rhs_lds, k_stage32_hi, 1);
    fla_u32x4 rhs_hi2 =
        read_h_stage32_doc<Element>(rhs_lds, k_stage32_hi, 2);
    fla_u32x4 rhs_hi3 =
        read_h_stage32_doc<Element>(rhs_lds, k_stage32_hi, 3);
    compiler_sched_barrier();

    wait_lgkmcnt_dep<4>(rhs_lo0, rhs_lo1, rhs_lo2, rhs_lo3);

    mmac_qpack_rhs_pack<Element>(q_pack_lo, rhs_lo0, acc[0]);
    mmac_qpack_rhs_pack<Element>(q_pack_lo, rhs_lo1, acc[1]);
    mmac_qpack_rhs_pack<Element>(q_pack_lo, rhs_lo2, acc[2]);
    mmac_qpack_rhs_pack<Element>(q_pack_lo, rhs_lo3, acc[3]);

    wait_lgkmcnt_dep<0>(rhs_hi0, rhs_hi1, rhs_hi2, rhs_hi3);

    mmac_qpack_rhs_pack<Element>(q_pack_hi, rhs_hi0, acc[0]);
    mmac_qpack_rhs_pack<Element>(q_pack_hi, rhs_hi1, acc[1]);
    mmac_qpack_rhs_pack<Element>(q_pack_hi, rhs_hi2, acc[2]);
    mmac_qpack_rhs_pack<Element>(q_pack_hi, rhs_hi3, acc[3]);
}

template <typename Element>
__device__ __forceinline__ void
mmac_qreg_k64_doc(const fla_u32x4 (&q_reg)[4],
                  Element *__restrict__ rhs_lds,
                  const int k_stage64, fla_f32x4 (&acc)[4])
{
    const int k_stage32_lo = k_stage64 * 2;
    const int k_stage32_hi = k_stage32_lo + 1;
    const fla_u32x4 q_pack_lo = q_reg[k_stage32_lo];
    const fla_u32x4 q_pack_hi = q_reg[k_stage32_hi];

    fla_u32x4 rhs_lo0 =
        read_k_stage32_doc<Element>(rhs_lds, k_stage32_lo, 0);
    fla_u32x4 rhs_lo1 =
        read_k_stage32_doc<Element>(rhs_lds, k_stage32_lo, 1);
    fla_u32x4 rhs_lo2 =
        read_k_stage32_doc<Element>(rhs_lds, k_stage32_lo, 2);
    fla_u32x4 rhs_lo3 =
        read_k_stage32_doc<Element>(rhs_lds, k_stage32_lo, 3);
    fla_u32x4 rhs_hi0 =
        read_k_stage32_doc<Element>(rhs_lds, k_stage32_hi, 0);
    fla_u32x4 rhs_hi1 =
        read_k_stage32_doc<Element>(rhs_lds, k_stage32_hi, 1);
    fla_u32x4 rhs_hi2 =
        read_k_stage32_doc<Element>(rhs_lds, k_stage32_hi, 2);
    fla_u32x4 rhs_hi3 =
        read_k_stage32_doc<Element>(rhs_lds, k_stage32_hi, 3);
    compiler_sched_barrier();

    wait_lgkmcnt_dep<4>(rhs_lo0, rhs_lo1, rhs_lo2, rhs_lo3);

    mmac_qpack_rhs_pack<Element>(q_pack_lo, rhs_lo0, acc[0]);
    mmac_qpack_rhs_pack<Element>(q_pack_lo, rhs_lo1, acc[1]);
    mmac_qpack_rhs_pack<Element>(q_pack_lo, rhs_lo2, acc[2]);
    mmac_qpack_rhs_pack<Element>(q_pack_lo, rhs_lo3, acc[3]);

    wait_lgkmcnt_dep<0>(rhs_hi0, rhs_hi1, rhs_hi2, rhs_hi3);

    mmac_qpack_rhs_pack<Element>(q_pack_hi, rhs_hi0, acc[0]);
    mmac_qpack_rhs_pack<Element>(q_pack_hi, rhs_hi1, acc[1]);
    mmac_qpack_rhs_pack<Element>(q_pack_hi, rhs_hi2, acc[2]);
    mmac_qpack_rhs_pack<Element>(q_pack_hi, rhs_hi3, acc[3]);
}

template <typename Element>
__device__ __forceinline__ void
mmac_a_v64_nmajor_alt_t32_doc(
    const typename fla_dtype_traits<Element>::vec4_t a_elem,
    Element *__restrict__ v_lds, const int t_half, fla_f32x4 (&acc)[4])
{
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;

    fla_u32x4 v_pack0 =
        read_v_stage32_nmajor_alt_doc<Element>(v_lds, t_half, 0);
    fla_u32x4 v_pack1 =
        read_v_stage32_nmajor_alt_doc<Element>(v_lds, t_half, 1);
    wait_lgkmcnt_dep<0>(v_pack0, v_pack1);

    ElementVec4 b = fla_vec4_from_pack<Element>(v_pack0, 0);
    fla_mmac_f32_16x16x16_accumulate<Element>(a_elem, b, acc[0]);
    b = fla_vec4_from_pack<Element>(v_pack0, 4);
    fla_mmac_f32_16x16x16_accumulate<Element>(a_elem, b, acc[1]);

    b = fla_vec4_from_pack<Element>(v_pack1, 0);
    fla_mmac_f32_16x16x16_accumulate<Element>(a_elem, b, acc[2]);
    b = fla_vec4_from_pack<Element>(v_pack1, 4);
    fla_mmac_f32_16x16x16_accumulate<Element>(a_elem, b, acc[3]);
}

template <typename Element, bool UseG, bool UseGGamma, bool UseExp2,
          bool UseSafeExp, int SBlock>
__device__ __forceinline__ typename fla_dtype_traits<Element>::vec4_t
make_av_a_stage_doc(const fla_f32x4 (&c_A)[4],
                    const float *__restrict__ g_lds_tile,
                    const float g_t, const float gamma_coeff,
                    const float av_scale, const int t_local,
                    const int lane_group)
{
    fla_f32x4 a_vals = {};
    constexpr int s_base = SBlock * 16;
    float gamma_delta = 0.0f;
    if constexpr (UseGGamma) {
        gamma_delta =
            gamma_coeff * float(t_local - (s_base + lane_group * 4));
    }
#pragma unroll
    for (int j = 0; j < 4; ++j) {
        const int s_col = s_base + lane_group * 4 + j;
        float a_val = c_A[j][SBlock];
        a_val = s_col <= t_local ? a_val : 0.0f;
        if (s_col <= t_local) {
            if constexpr (UseG) {
                a_val *= gate_delta_exp<UseExp2, UseSafeExp>(
                    g_t - g_lds_tile[s_col]);
            }
            if constexpr (UseGGamma) {
                a_val *= gate_delta_exp<UseExp2, false>(gamma_delta);
            }
        }
        if constexpr (UseGGamma) {
            gamma_delta -= gamma_coeff;
        }
        a_val *= av_scale;
        a_vals[j] = a_val;
    }
    return fla_pack_f32x4_to_element_vec4<Element>(a_vals);
}

template <typename Element, bool UseG, bool UseGGamma, bool UseExp2,
          bool UseSafeExp>
__device__ __forceinline__ typename fla_dtype_traits<Element>::vec4_t
make_av_a_stage_doc_switch(const fla_f32x4 (&c_A)[4],
                           const float *__restrict__ g_lds_tile,
                           const float g_t, const float gamma_coeff,
                           const float av_scale, const int t_local,
                           const int lane_group, const int s_block)
{
    if (s_block == 0) {
        return make_av_a_stage_doc<Element, UseG, UseGGamma, UseExp2,
                                   UseSafeExp, 0>(
            c_A, g_lds_tile, g_t, gamma_coeff, av_scale, t_local,
            lane_group);
    }
    if (s_block == 1) {
        return make_av_a_stage_doc<Element, UseG, UseGGamma, UseExp2,
                                   UseSafeExp, 1>(
            c_A, g_lds_tile, g_t, gamma_coeff, av_scale, t_local,
            lane_group);
    }
    if (s_block == 2) {
        return make_av_a_stage_doc<Element, UseG, UseGGamma, UseExp2,
                                   UseSafeExp, 2>(
            c_A, g_lds_tile, g_t, gamma_coeff, av_scale, t_local,
            lane_group);
    }
    return make_av_a_stage_doc<Element, UseG, UseGGamma, UseExp2,
                               UseSafeExp, 3>(
        c_A, g_lds_tile, g_t, gamma_coeff, av_scale, t_local, lane_group);
}

template <bool IsVarlen, bool UseChunkIndices, bool SingleSeqVarlen,
          bool FullChunk>
class ChunkFwdOBlockInfo
{
public:
    using index_t = ChunkFwdOParams::index_t;

    __device__ __forceinline__
    ChunkFwdOBlockInfo(const ChunkFwdOParams &params, const int v_group,
                       const int chunk_grid, const int z)
        : v_group_(v_group)
    {
        init_sequence(params, chunk_grid, z);
        if (!valid_) {
            return;
        }

        t_begin_ = chunk_ * params.BT;
        if constexpr (FullChunk) {
            valid_t_ = params.BT;
        } else {
            valid_t_ = min(params.BT, seqlen_ - t_begin_);
            if (valid_t_ <= 0) {
                valid_ = false;
                return;
            }
        }

        const int head_per_group = params.H / params.Hg;
        if (head_per_group == 1) {
            qk_head_ = head_;
        } else if (head_per_group == 2) {
            qk_head_ = head_ >> 1;
        } else if (head_per_group == 4) {
            qk_head_ = head_ >> 2;
        } else if (head_per_group == 8) {
            qk_head_ = head_ >> 3;
        } else {
            qk_head_ = head_ / head_per_group;
        }

        init_tensor_offsets(params);
    }

    __device__ __forceinline__ bool valid() const { return valid_; }
    __device__ __forceinline__ int v_group() const { return v_group_; }
    __device__ __forceinline__ int head() const { return head_; }
    __device__ __forceinline__ int qk_head() const { return qk_head_; }
    __device__ __forceinline__ int chunk() const { return chunk_; }
    __device__ __forceinline__ int global_chunk() const { return global_chunk_; }
    __device__ __forceinline__ int bos() const { return bos_; }
    __device__ __forceinline__ int seqlen() const { return seqlen_; }
    __device__ __forceinline__ int t_begin() const { return t_begin_; }
    __device__ __forceinline__ int valid_t() const { return valid_t_; }

    __device__ __forceinline__ index_t q_tile_base() const { return q_tile_base_; }
    __device__ __forceinline__ index_t k_tile_base() const { return k_tile_base_; }
    __device__ __forceinline__ index_t v_tile_base() const { return v_tile_base_; }
    __device__ __forceinline__ index_t h_base() const { return h_base_; }

    __device__ __forceinline__ bool valid_row(const int t_local) const
    {
        return t_local < valid_t_;
    }

    __device__ __forceinline__
    index_t o_offset(const ChunkFwdOParams &params, const int t_local) const
    {
        return o_tile_base_ + index_t(t_local) * params.o_row_stride;
    }

    __device__ __forceinline__
    index_t g_offset(const ChunkFwdOParams &params, const int t_local) const
    {
        return g_tile_base_ + index_t(t_local) * params.g_row_stride;
    }

private:
    __device__ __forceinline__
    int load_cu_seqlen(const ChunkFwdOParams &params, const int idx) const
    {
        if (params.cu_seqlens_i64) {
            const int64_t *__restrict__ cu =
                reinterpret_cast<const int64_t *>(params.cu_seqlens);
            return static_cast<int>(cu[idx]);
        }
        const int *__restrict__ cu =
            reinterpret_cast<const int *>(params.cu_seqlens);
        return cu[idx];
    }

    __device__ __forceinline__
    void init_sequence(const ChunkFwdOParams &params, const int chunk_grid,
                       const int z)
    {
        const int chunk_grid_with_offset = chunk_grid + params.chunk_start;
        if constexpr (IsVarlen) {
            const int wave_lane = threadIdx.x & 63;
            int seq_begin = 0;
            int seq_end = 0;
            if constexpr (SingleSeqVarlen) {
                seq_or_batch_ = 0;
                head_ = z;
                if (wave_lane == 0) {
                    seq_begin = load_cu_seqlen(params, 0);
                    seq_end = load_cu_seqlen(params, 1);
                }
            } else if constexpr (UseChunkIndices) {
                head_ = z;
                int seq_or_batch = 0;
                int chunk = 0;
                if (params.chunk_indices_i64) {
                    const int64_t *__restrict__ ci =
                        reinterpret_cast<const int64_t *>(params.chunk_indices);
                    if (wave_lane == 0) {
                        seq_or_batch =
                            static_cast<int>(ci[chunk_grid_with_offset * 2]);
                        chunk = static_cast<int>(
                            ci[chunk_grid_with_offset * 2 + 1]);
                    }
                } else {
                    const int *__restrict__ ci =
                        reinterpret_cast<const int *>(params.chunk_indices);
                    if (wave_lane == 0) {
                        seq_or_batch = ci[chunk_grid_with_offset * 2];
                        chunk = ci[chunk_grid_with_offset * 2 + 1];
                    }
                }
                seq_or_batch_ = __shfl(seq_or_batch, 0, 64);
                chunk_ = __shfl(chunk, 0, 64);
                global_chunk_ = chunk_grid_with_offset;
                if (wave_lane == 0) {
                    seq_begin = load_cu_seqlen(params, seq_or_batch_);
                    seq_end = load_cu_seqlen(params, seq_or_batch_ + 1);
                }
            } else {
                seq_or_batch_ = z / params.H;
                head_ = z - seq_or_batch_ * params.H;
                if (wave_lane == 0) {
                    seq_begin = load_cu_seqlen(params, seq_or_batch_);
                    seq_end = load_cu_seqlen(params, seq_or_batch_ + 1);
                }
            }

            seq_begin = __shfl(seq_begin, 0, 64);
            seq_end = __shfl(seq_end, 0, 64);
            if constexpr (SingleSeqVarlen) {
                chunk_ = chunk_grid_with_offset;
                global_chunk_ = chunk_grid_with_offset;
            } else if constexpr (!UseChunkIndices) {
                const int chunk_count =
                    (seq_end - seq_begin + params.BT - 1) / params.BT;
                if (chunk_grid_with_offset >= chunk_count) {
                    valid_ = false;
                    return;
                }
                chunk_ = chunk_grid_with_offset;
                global_chunk_ = params.chunk_offsets == nullptr
                    ? chunk_grid_with_offset
                    : params.chunk_offsets[seq_or_batch_] + chunk_grid_with_offset;
            }

            bos_ = seq_begin;
            seqlen_ = seq_end - seq_begin;
        } else {
            if (params.N == 1) {
                seq_or_batch_ = 0;
                head_ = z;
            } else {
                seq_or_batch_ = z / params.H;
                head_ = z - seq_or_batch_ * params.H;
            }
            chunk_ = chunk_grid_with_offset;
            global_chunk_ = chunk_grid_with_offset;
            bos_ = seq_or_batch_ * params.T;
            seqlen_ = params.T;
        }
    }

    __device__ __forceinline__
    void init_tensor_offsets(const ChunkFwdOParams &params)
    {
        if constexpr (IsVarlen) {
            const index_t row = index_t(bos_ + t_begin_);
            q_tile_base_ = row * params.q_row_stride +
                           index_t(qk_head_) * params.q_head_stride;
            k_tile_base_ = row * params.k_row_stride +
                           index_t(qk_head_) * params.k_head_stride;
            v_tile_base_ = row * params.v_row_stride +
                           index_t(head_) * params.v_head_stride;
            h_base_ = index_t(global_chunk_) * params.h_chunk_stride +
                      index_t(head_) * params.h_head_stride;
            o_tile_base_ = row * params.o_row_stride +
                           index_t(head_) * params.o_head_stride;
            g_tile_base_ = row * params.g_row_stride + head_;
        } else {
            q_tile_base_ =
                index_t(seq_or_batch_) * params.q_batch_stride +
                index_t(t_begin_) * params.q_row_stride +
                index_t(qk_head_) * params.q_head_stride;
            k_tile_base_ =
                index_t(seq_or_batch_) * params.k_batch_stride +
                index_t(t_begin_) * params.k_row_stride +
                index_t(qk_head_) * params.k_head_stride;
            v_tile_base_ =
                index_t(seq_or_batch_) * params.v_batch_stride +
                index_t(t_begin_) * params.v_row_stride +
                index_t(head_) * params.v_head_stride;
            h_base_ =
                index_t(seq_or_batch_) * params.h_batch_stride +
                index_t(chunk_) * params.h_chunk_stride +
                index_t(head_) * params.h_head_stride;
            o_tile_base_ =
                index_t(seq_or_batch_) * params.o_batch_stride +
                index_t(t_begin_) * params.o_row_stride +
                index_t(head_) * params.o_head_stride;
            g_tile_base_ =
                index_t(seq_or_batch_) * params.g_batch_stride +
                index_t(t_begin_) * params.g_row_stride + head_;
        }
    }

    bool valid_ = true;
    int v_group_ = 0;
    int seq_or_batch_ = 0;
    int head_ = 0;
    int qk_head_ = 0;
    int chunk_ = 0;
    int global_chunk_ = 0;
    int bos_ = 0;
    int seqlen_ = 0;
    int t_begin_ = 0;
    int valid_t_ = 0;
    index_t q_tile_base_ = 0;
    index_t k_tile_base_ = 0;
    index_t v_tile_base_ = 0;
    index_t h_base_ = 0;
    index_t o_tile_base_ = 0;
    index_t g_tile_base_ = 0;
};

template <typename Element, bool UseG, bool UseGGamma, bool UseExp2,
          bool IsVarlen, bool UseChunkIndices, bool SingleSeqVarlen,
          bool UseSafeExp, bool FullChunk>
__global__ __launch_bounds__(256)
void chunk_fwd_o_demo_kernel(const ChunkFwdOParams params)
{
    constexpr int BK = 128;
    constexpr int BT = 64;
    constexpr int BV = 64;
    constexpr int BV_STAGE = 32;
    constexpr int kNWarps = 4;
    constexpr int RHS_STRIDE = BK;

    using index_t = ChunkFwdOParams::index_t;
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;

    const int tid = threadIdx.x;
    const int warp_id = tid >> 6;
    const int lane_id = tid & 63;
    const int lane_m = lane_id & 15;
    const int lane_group = lane_id >> 4;

    const int v_group = blockIdx.x;
    const int chunk_grid = blockIdx.y;
    const int z = blockIdx.z;

    const ChunkFwdOBlockInfo<IsVarlen, UseChunkIndices, SingleSeqVarlen,
                             FullChunk> binfo(
        params, v_group, chunk_grid, z);
    if (!binfo.valid()) {
        return;
    }

    const int head = binfo.head();
    const int t_local = warp_id * 16 + lane_m;

    const Element *__restrict__ q = reinterpret_cast<const Element *>(params.q_ptr);
    const Element *__restrict__ k = reinterpret_cast<const Element *>(params.k_ptr);
    const Element *__restrict__ v = reinterpret_cast<const Element *>(params.v_ptr);
    const Element *__restrict__ h = reinterpret_cast<const Element *>(params.h_ptr);
    Element *__restrict__ o = reinterpret_cast<Element *>(params.o_ptr);

    const index_t q_tile_base = binfo.q_tile_base();
    const index_t k_tile_base = binfo.k_tile_base();
    const index_t v_tile_base = binfo.v_tile_base();
    const index_t h_base = binfo.h_base();
    const index_t o_row = binfo.o_offset(params, t_local);

    extern __shared__ uint8_t lds_base[];
    constexpr int RHS_STAGE_K = 64;
    constexpr int RHS_STAGE_COUNT = BK / RHS_STAGE_K;
    constexpr int RHS_LDS_ELEMENTS = RHS_STAGE_COUNT * RHS_STAGE_K * BV;
    constexpr int V_STAGE_ELEMENTS = BV_STAGE * BV;
    Element *rhs_lds_tile = reinterpret_cast<Element *>(lds_base);
    Element *v_lds_stage0 = rhs_lds_tile;
    Element *v_lds_stage1 = rhs_lds_tile + V_STAGE_ELEMENTS;
    float *g_lds_tile = reinterpret_cast<float *>(rhs_lds_tile);

    fla_u32x4 q_reg[4];
#pragma unroll
    for (int k_stage32 = 0; k_stage32 < 4; ++k_stage32) {
        if constexpr (FullChunk) {
            q_reg[k_stage32] = load_q_reg_stage<Element, true>(
                q, q_tile_base, params.q_row_stride, k_stage32,
                binfo.valid_t());
        } else {
            q_reg[k_stage32] = load_q_reg_stage<Element, false>(
                q, q_tile_base, params.q_row_stride, k_stage32,
                binfo.valid_t());
        }
    }

    fla_f32x4 c_o[4] = {
        {0.0f, 0.0f, 0.0f, 0.0f},
        {0.0f, 0.0f, 0.0f, 0.0f},
        {0.0f, 0.0f, 0.0f, 0.0f},
        {0.0f, 0.0f, 0.0f, 0.0f}};
    fla_f32x4 c_A[4] = {
        {0.0f, 0.0f, 0.0f, 0.0f},
        {0.0f, 0.0f, 0.0f, 0.0f},
        {0.0f, 0.0f, 0.0f, 0.0f},
        {0.0f, 0.0f, 0.0f, 0.0f}};

    const Element *__restrict__ h_rhs =
        h + h_base + index_t(v_group * BV) * params.K;
    const Element *__restrict__ k_rhs = k + k_tile_base;

    prefetch_h_stage64_to_lds_doc<Element>(
        rhs_lds_tile, h_rhs, 0);
    prefetch_h_stage64_to_lds_doc<Element>(
        rhs_lds_tile, h_rhs, 1);
    const fla_u32x4 k0_area0 =
        load_k_stage64_area_to_vgpr_doc<Element, FullChunk>(
            k_rhs, params.k_row_stride, 0, binfo.valid_t(), 0);
    const fla_u32x4 k0_area1 =
        load_k_stage64_area_to_vgpr_doc<Element, FullChunk>(
            k_rhs, params.k_row_stride, 0, binfo.valid_t(), 1);
    const fla_u32x4 k1_area0 =
        load_k_stage64_area_to_vgpr_doc<Element, FullChunk>(
            k_rhs, params.k_row_stride, 1, binfo.valid_t(), 0);
    const fla_u32x4 k1_area1 =
        load_k_stage64_area_to_vgpr_doc<Element, FullChunk>(
            k_rhs, params.k_row_stride, 1, binfo.valid_t(), 1);
    compiler_sched_barrier();
    wait_vmcnt_barrier<6>();

    mmac_qreg_h64_doc<Element>(q_reg, rhs_lds_tile, 0, c_o);
    compiler_sched_barrier();
    wait_vmcnt_lgkmcnt0_barrier<2>();
    write_k_stage64_area_from_vgpr_doc<Element>(rhs_lds_tile, k0_area0, 0,
                                                0);
    write_k_stage64_area_from_vgpr_doc<Element>(rhs_lds_tile, k0_area1, 0,
                                                1);
    compiler_sched_barrier();

    mmac_qreg_h64_doc<Element>(q_reg, rhs_lds_tile, 1, c_o);
    compiler_sched_barrier();
    wait_vmcnt_lgkmcnt0_barrier<0>();
    write_k_stage64_area_from_vgpr_doc<Element>(rhs_lds_tile, k1_area0, 1,
                                                0);
    write_k_stage64_area_from_vgpr_doc<Element>(rhs_lds_tile, k1_area1, 1,
                                                1);
    compiler_sched_barrier();
    wait_lgkmcnt0_barrier();

    mmac_qreg_k64_doc<Element>(q_reg, rhs_lds_tile, 0, c_A);
    compiler_sched_barrier();
    wait_lgkmcnt0_barrier();

    if constexpr (UseG) {
        const float *__restrict__ g = reinterpret_cast<const float *>(params.g_ptr);
        if (tid < BT) {
            if constexpr (FullChunk) {
                g_lds_tile[tid] = g[binfo.g_offset(params, tid)];
            } else {
                g_lds_tile[tid] = tid < binfo.valid_t()
                    ? g[binfo.g_offset(params, tid)]
                    : 0.0f;
            }
        }
        compiler_sched_barrier();
    }

    mmac_qreg_k64_doc<Element>(q_reg, rhs_lds_tile, 1, c_A);
    if constexpr (UseG) {
        wait_all_and_barrier();
    } else {
        wait_lgkmcnt0_barrier();
    }

    float g_t = 0.0f;
    if constexpr (UseG) {
        g_t = g_lds_tile[t_local];
    }
    float gamma_coeff = 0.0f;
    float gamma_t = 0.0f;
    if constexpr (UseGGamma) {
        gamma_coeff = reinterpret_cast<const float *>(params.g_gamma_ptr)[head];
        gamma_t = gamma_coeff * float(t_local + 1);
    }

    float state_scale = params.scale;
    if constexpr (UseG) {
        state_scale *= gate_exp<UseExp2>(g_t);
    }
    if constexpr (UseGGamma) {
        state_scale *= gate_exp<UseExp2>(gamma_t);
    }
    const float av_scale = params.scale;

#pragma unroll
    for (int i = 0; i < 4; ++i) {
#pragma unroll
        for (int j = 0; j < 4; ++j) {
            c_o[i][j] *= state_scale;
        }
    }

    ElementVec4 a_stage0 =
        make_av_a_stage_doc<Element, UseG, UseGGamma, UseExp2, UseSafeExp, 0>(
            c_A, g_lds_tile, g_t, gamma_coeff, av_scale, t_local,
            lane_group);
    ElementVec4 a_stage1 =
        make_av_a_stage_doc<Element, UseG, UseGGamma, UseExp2, UseSafeExp, 1>(
            c_A, g_lds_tile, g_t, gamma_coeff, av_scale, t_local,
            lane_group);
    ElementVec4 a_stage2 =
        make_av_a_stage_doc<Element, UseG, UseGGamma, UseExp2, UseSafeExp, 2>(
            c_A, g_lds_tile, g_t, gamma_coeff, av_scale, t_local,
            lane_group);
    ElementVec4 a_stage3 =
        make_av_a_stage_doc<Element, UseG, UseGGamma, UseExp2, UseSafeExp, 3>(
            c_A, g_lds_tile, g_t, gamma_coeff, av_scale, t_local,
            lane_group);

    prefetch_v_stage32_to_lds_doc<Element, FullChunk>(
        v_lds_stage0, v + v_tile_base + index_t(v_group * BV),
        params.v_row_stride, 0, binfo.valid_t());
    compiler_sched_barrier();
    wait_vmcnt_barrier<0>();

    prefetch_v_stage32_to_lds_doc<Element, FullChunk>(
        v_lds_stage1, v + v_tile_base + index_t(v_group * BV),
        params.v_row_stride, BV_STAGE, binfo.valid_t());
    compiler_sched_barrier();

    mmac_a_v64_nmajor_alt_t32_doc<Element>(
        a_stage0, v_lds_stage0, 0, c_o);
    mmac_a_v64_nmajor_alt_t32_doc<Element>(
        a_stage1, v_lds_stage0, 1, c_o);

    wait_vmcnt_barrier<0>();

    mmac_a_v64_nmajor_alt_t32_doc<Element>(
        a_stage2, v_lds_stage1, 0, c_o);
    mmac_a_v64_nmajor_alt_t32_doc<Element>(
        a_stage3, v_lds_stage1, 1, c_o);

    const fla_u32x4 packed_low = {
        fla_pack_element_x2_bits<Element>(fla_f32x2{c_o[0][0], c_o[1][0]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{c_o[0][1], c_o[1][1]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{c_o[0][2], c_o[1][2]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{c_o[0][3], c_o[1][3]})};
    const fla_u32x4 packed_high = {
        fla_pack_element_x2_bits<Element>(fla_f32x2{c_o[2][0], c_o[3][0]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{c_o[2][1], c_o[3][1]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{c_o[2][2], c_o[3][2]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{c_o[2][3], c_o[3][3]})};

    const fla_u32x4 out_low =
        fla_make_packed_projection_u32x4(packed_low, lane_group);
    const fla_u32x4 out_high =
        fla_make_packed_projection_u32x4(packed_high, lane_group);

    const int v_col_base = v_group * BV + lane_group * 8;
    if constexpr (FullChunk) {
        store_packed_v8_no_oob<Element>(o, o_row, v_col_base, out_low);
        store_packed_v8_no_oob<Element>(o, o_row, v_col_base + 32, out_high);
    } else if (binfo.valid_row(t_local)) {
        store_packed_v8_no_oob<Element>(o, o_row, v_col_base, out_low);
        store_packed_v8_no_oob<Element>(o, o_row, v_col_base + 32, out_high);
    }
}

}  // namespace FLA_NAMESPACE
