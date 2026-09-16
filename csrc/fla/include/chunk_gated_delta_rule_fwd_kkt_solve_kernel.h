// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#pragma once

#include "fla.h"
#include "utils.h"

#include <cstdint>
#include <type_traits>

namespace FLA_NAMESPACE {

constexpr int kKktBC = 16;
constexpr int kKktMaxBT = 64;
constexpr int kKktBK = 128;
constexpr int kKktStageK = 64;
constexpr int kKktRhsLdsElements = kKktMaxBT * kKktBK;

// Scratch stores the 10 lower-triangular 16x16 blocks of a 64x64 tile,
// followed by three temporary blocks used by the merge solve.
constexpr int kKktNumTriBlocks = 10;
constexpr int kKktTemp0Block = kKktNumTriBlocks + 0;
constexpr int kKktTemp1Block = kKktNumTriBlocks + 1;
constexpr int kKktTemp2Block = kKktNumTriBlocks + 2;
constexpr int kKktNumScratchBlocks = kKktNumTriBlocks + 3;

// Each 16x16 scratch block has one padding slot per 32 logical elements.
constexpr int kKktScratchPadInterval = 32;
constexpr int kKktScratchBlockElements =
    kKktBC * kKktBC + (kKktBC * kKktBC) / kKktScratchPadInterval;
constexpr int kKktScratchElements =
    kKktNumScratchBlocks * kKktScratchBlockElements;

// beta/g are cached after the scratch area, aligned to a 32-float boundary.
constexpr int kKktScaleHeadCap = 2;
constexpr int kKktScaleElements = kKktMaxBT * 2 * kKktScaleHeadCap;
constexpr int kKktScaleOffset = ((kKktScratchElements + 31) / 32) * 32;
constexpr int kKktScratchWithScaleElements =
    kKktScaleOffset + kKktScaleElements;

template <typename T>
__device__ __forceinline__ float kkt_to_float(T x)
{
    return ck_tile::type_convert<float>(x);
}

__device__ __forceinline__ int kkt_tri_block_id(int row_block, int col_block)
{
    return row_block * (row_block + 1) / 2 + col_block;
}

__device__ __forceinline__ float* kkt_scratch_block(float* scratch, int id)
{
    return scratch + id * kKktScratchBlockElements;
}

__device__ __forceinline__ const float* kkt_scratch_block_const(const float* scratch, int id)
{
    return scratch + id * kKktScratchBlockElements;
}

template <bool SwizzleScratch>
__device__ __forceinline__ int kkt_scratch_offset(const int row, const int col)
{
    if constexpr (SwizzleScratch) {
        const int col_swizzled =
            ((col & 3) << 1) + ((col >> 2) & 1) + ((col >> 3) << 3);
        const int linear = row * kKktBC + col_swizzled;
        return linear + (linear >> 5);
    } else {
        const int linear = row * kKktBC + col;
        return linear + (linear >> 5);
    }
}

__device__ __forceinline__ int kkt_scratch_offset(const int row, const int col)
{
    return kkt_scratch_offset<false>(row, col);
}

template <bool SwizzleScratch>
__device__ __forceinline__ int kkt_scratch_linear_offset(const int element)
{
    return kkt_scratch_offset<SwizzleScratch>(element >> 4, element & 15);
}

__device__ __forceinline__ int kkt_scratch_linear_offset(const int element)
{
    return kkt_scratch_linear_offset<false>(element);
}

template <typename Element, bool FullRows>
__device__ __forceinline__ fla_u32x4 kkt_load_k_reg_stage(
    const Element* __restrict__ k_gmem,
    const int k_t_stride,
    const int k_stage32,
    const int valid_t)
{
    const int lane_id = static_cast<int>(threadIdx.x) & 63;
    const int lane_m = lane_id & 15;
    const int lane_k_group = lane_id >> 4;
    const int warp_id = static_cast<int>(threadIdx.x) >> 6;
    const int row = warp_id * 16 + lane_m;
    const int k_point = k_stage32 * 4 + lane_k_group;
    const int element_offset = row * k_t_stride + k_point * 8;
    const int32_t offset_bytes = (FullRows || row < valid_t)
        ? static_cast<int32_t>(element_offset * static_cast<int>(sizeof(Element)))
        : -1;
    const fla_buffer_accessor buffer(k_gmem);
    return fla_buffer_load_dwordx4_vgpr_inline(buffer.buffer_res, offset_bytes);
}

template <typename Element, bool FullRows>
__device__ __forceinline__ void kkt_prefetch_k_stage64_to_lds(
    Element* __restrict__ rhs_lds,
    const Element* __restrict__ k_gmem,
    const int k_t_stride,
    const int k_stage64,
    const int valid_t)
{
    constexpr int kElemsPerPoint = 8;
    constexpr int kStageKPoints = kKktStageK / kElemsPerPoint;
    constexpr int kSlotsPerArea = 64;
    constexpr int kNWarps = 4;
    constexpr int kStagePoints = kStageKPoints * kKktMaxBT;
    constexpr int kStageBytes =
        kStagePoints * kElemsPerPoint * static_cast<int>(sizeof(Element));
    constexpr int kAreaBytes =
        kSlotsPerArea * kElemsPerPoint * static_cast<int>(sizeof(Element));

    const int lane_id = static_cast<int>(threadIdx.x) & 63;
    const int warp_id = __builtin_amdgcn_readfirstlane(
        static_cast<int>(threadIdx.x)) >> 6;
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
            t_local * k_t_stride +
            k_stage64 * kKktStageK + k_point * kElemsPerPoint;
        // Only row blocks that are consumed by a lower row block need to be
        // published to RHS LDS; each diagonal block uses this wave's q_reg.
        const int rhs_limit = FullRows
            ? kKktMaxBT - kKktBC
            : ((valid_t - 1) / kKktBC) * kKktBC;
        if (t_local < rhs_limit) {
            const int offset_v = element_offset * static_cast<int>(sizeof(Element));
            const int target_addr =
                lds_base + k_stage64 * kStageBytes + area * kAreaBytes +
                (area << 16);
            fla_buffer_load_dwordx4_to_lds_inline(
                buffer.buffer_res, target_addr, offset_v);
        }
    }
}

__device__ __forceinline__ int kkt_k_move_area_from_tn(const int t_n)
{
    return (t_n & 31) >> 2;
}

__device__ __forceinline__ int kkt_k_move_slot_from_tn_kpoint(
    const int t_n, const int k_point)
{
    return (((t_n >> 5) << 2) + (t_n & 3)) * 8 + k_point;
}

template <typename Element>
__device__ __forceinline__ fla_u32x4 kkt_read_k_stage32(
    Element* __restrict__ rhs_lds,
    const int k_stage32,
    const int acc_id)
{
    constexpr int kElemsPerPoint = 8;
    constexpr int kStageKPoints = kKktStageK / kElemsPerPoint;
    constexpr int kSlotsPerArea = 64;
    constexpr int kStagePoints = kStageKPoints * kKktMaxBT;

    const int lane_id = static_cast<int>(threadIdx.x) & 63;
    const int lane_n = lane_id & 15;
    const int lane_k_group = lane_id >> 4;
    const int t_n = lane_n * 4 + acc_id;
    const int logical_group8 = k_stage32 * 4 + lane_k_group;
    const int k_stage64 = logical_group8 >> 3;
    const int k_point = logical_group8 & 7;
    const int area = kkt_k_move_area_from_tn(t_n);
    const int producer_lane = kkt_k_move_slot_from_tn_kpoint(t_n, k_point);
    const int wrapped_slot = (producer_lane + area) & (kSlotsPerArea - 1);
    const int lds_point =
        k_stage64 * kStagePoints + area * kSlotsPerArea + wrapped_slot;
    return fla_ds_read_b128_asm<Element>(rhs_lds + lds_point * kElemsPerPoint);
}

template <typename Element, int NBlock>
__device__ __forceinline__ fla_u32x4 kkt_read_k_stage32_nblock(
    Element* __restrict__ rhs_lds,
    const int k_stage32)
{
    constexpr int kElemsPerPoint = 8;
    constexpr int kStageKPoints = kKktStageK / kElemsPerPoint;
    constexpr int kSlotsPerArea = 64;
    constexpr int kStagePoints = kStageKPoints * kKktMaxBT;

    const int lane_id = static_cast<int>(threadIdx.x) & 63;
    const int lane_n = lane_id & 15;
    const int lane_k_group = lane_id >> 4;
    const int t_n = NBlock * kKktBC + lane_n;
    const int logical_group8 = k_stage32 * 4 + lane_k_group;
    const int k_stage64 = logical_group8 >> 3;
    const int k_point = logical_group8 & 7;
    const int area = kkt_k_move_area_from_tn(t_n);
    const int producer_lane = kkt_k_move_slot_from_tn_kpoint(t_n, k_point);
    const int wrapped_slot = (producer_lane + area) & (kSlotsPerArea - 1);
    const int lds_point =
        k_stage64 * kStagePoints + area * kSlotsPerArea + wrapped_slot;
    return fla_ds_read_b128_asm<Element>(rhs_lds + lds_point * kElemsPerPoint);
}

template <typename Element>
__device__ __forceinline__ void kkt_mmac_qpack_kpack(
    const fla_u32x4 q_pack,
    const fla_u32x4 rhs_pack,
    fla_f32x4& acc)
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
__device__ __forceinline__ void kkt_mmac_qreg_k64(
    const fla_u32x4 (&q_reg)[4],
    Element* __restrict__ rhs_lds,
    const int k_stage64,
    fla_f32x4 (&acc)[4])
{
    const int k_stage32_lo = k_stage64 * 2;
    const int k_stage32_hi = k_stage32_lo + 1;
    const fla_u32x4 q_pack_lo = q_reg[k_stage32_lo];
    const fla_u32x4 q_pack_hi = q_reg[k_stage32_hi];
    const int warp_id = static_cast<int>(threadIdx.x) >> 6;

    if (warp_id < 2) {
        fla_u32x4 rhs_lo0 =
            kkt_read_k_stage32<Element>(rhs_lds, k_stage32_lo, 0);
        fla_u32x4 rhs_lo1 =
            kkt_read_k_stage32<Element>(rhs_lds, k_stage32_lo, 1);
        fla_u32x4 rhs_hi0 =
            kkt_read_k_stage32<Element>(rhs_lds, k_stage32_hi, 0);
        fla_u32x4 rhs_hi1 =
            kkt_read_k_stage32<Element>(rhs_lds, k_stage32_hi, 1);
        compiler_sched_barrier();

        wait_lgkmcnt_dep<2>(rhs_lo0, rhs_lo1);

        kkt_mmac_qpack_kpack<Element>(q_pack_lo, rhs_lo0, acc[0]);
        kkt_mmac_qpack_kpack<Element>(q_pack_lo, rhs_lo1, acc[1]);

        wait_lgkmcnt_dep<0>(rhs_hi0, rhs_hi1);

        kkt_mmac_qpack_kpack<Element>(q_pack_hi, rhs_hi0, acc[0]);
        kkt_mmac_qpack_kpack<Element>(q_pack_hi, rhs_hi1, acc[1]);
        return;
    }

    fla_u32x4 rhs_lo0 = kkt_read_k_stage32<Element>(rhs_lds, k_stage32_lo, 0);
    fla_u32x4 rhs_lo1 = kkt_read_k_stage32<Element>(rhs_lds, k_stage32_lo, 1);
    fla_u32x4 rhs_lo2 = kkt_read_k_stage32<Element>(rhs_lds, k_stage32_lo, 2);
    fla_u32x4 rhs_lo3 = kkt_read_k_stage32<Element>(rhs_lds, k_stage32_lo, 3);
    fla_u32x4 rhs_hi0 = kkt_read_k_stage32<Element>(rhs_lds, k_stage32_hi, 0);
    fla_u32x4 rhs_hi1 = kkt_read_k_stage32<Element>(rhs_lds, k_stage32_hi, 1);
    fla_u32x4 rhs_hi2 = kkt_read_k_stage32<Element>(rhs_lds, k_stage32_hi, 2);
    fla_u32x4 rhs_hi3 = kkt_read_k_stage32<Element>(rhs_lds, k_stage32_hi, 3);
    compiler_sched_barrier();

    wait_lgkmcnt_dep<4>(rhs_lo0, rhs_lo1, rhs_lo2, rhs_lo3);

    kkt_mmac_qpack_kpack<Element>(q_pack_lo, rhs_lo0, acc[0]);
    kkt_mmac_qpack_kpack<Element>(q_pack_lo, rhs_lo1, acc[1]);
    kkt_mmac_qpack_kpack<Element>(q_pack_lo, rhs_lo2, acc[2]);
    kkt_mmac_qpack_kpack<Element>(q_pack_lo, rhs_lo3, acc[3]);

    wait_lgkmcnt_dep<0>(rhs_hi0, rhs_hi1, rhs_hi2, rhs_hi3);

    kkt_mmac_qpack_kpack<Element>(q_pack_hi, rhs_hi0, acc[0]);
    kkt_mmac_qpack_kpack<Element>(q_pack_hi, rhs_hi1, acc[1]);
    kkt_mmac_qpack_kpack<Element>(q_pack_hi, rhs_hi2, acc[2]);
    kkt_mmac_qpack_kpack<Element>(q_pack_hi, rhs_hi3, acc[3]);
}

template <typename Element>
__device__ __forceinline__ void kkt_mmac_qreg_k64_lower_nblocks(
    const fla_u32x4 (&q_reg)[4],
    Element* __restrict__ rhs_lds,
    const int k_stage64,
    fla_f32x4 (&acc)[4])
{
    const int k_stage32_lo = k_stage64 * 2;
    const int k_stage32_hi = k_stage32_lo + 1;
    const fla_u32x4 q_pack_lo = q_reg[k_stage32_lo];
    const fla_u32x4 q_pack_hi = q_reg[k_stage32_hi];
    const int rb = static_cast<int>(threadIdx.x) >> 6;

    if (rb == 0) {
        // Diagonal nblock == rb is the same K row block already resident in
        // q_reg, so avoid a redundant RHS LDS read.
        kkt_mmac_qpack_kpack<Element>(q_pack_lo, q_pack_lo, acc[0]);
        kkt_mmac_qpack_kpack<Element>(q_pack_hi, q_pack_hi, acc[0]);
        return;
    }

    if (rb == 1) {
        fla_u32x4 rhs_lo0 =
            kkt_read_k_stage32_nblock<Element, 0>(rhs_lds, k_stage32_lo);
        fla_u32x4 rhs_hi0 =
            kkt_read_k_stage32_nblock<Element, 0>(rhs_lds, k_stage32_hi);
        compiler_sched_barrier();

        wait_lgkmcnt_dep<1>(rhs_lo0, rhs_hi0);
        kkt_mmac_qpack_kpack<Element>(q_pack_lo, rhs_lo0, acc[0]);
        kkt_mmac_qpack_kpack<Element>(q_pack_lo, q_pack_lo, acc[1]);
        wait_lgkmcnt_dep<0>(rhs_lo0, rhs_hi0);
        kkt_mmac_qpack_kpack<Element>(q_pack_hi, rhs_hi0, acc[0]);
        kkt_mmac_qpack_kpack<Element>(q_pack_hi, q_pack_hi, acc[1]);
        return;
    }

    if (rb == 2) {
        fla_u32x4 rhs_lo0 =
            kkt_read_k_stage32_nblock<Element, 0>(rhs_lds, k_stage32_lo);
        fla_u32x4 rhs_lo1 =
            kkt_read_k_stage32_nblock<Element, 1>(rhs_lds, k_stage32_lo);
        fla_u32x4 rhs_hi0 =
            kkt_read_k_stage32_nblock<Element, 0>(rhs_lds, k_stage32_hi);
        fla_u32x4 rhs_hi1 =
            kkt_read_k_stage32_nblock<Element, 1>(rhs_lds, k_stage32_hi);
        compiler_sched_barrier();

        wait_lgkmcnt_dep<2>(rhs_lo0, rhs_lo1);
        kkt_mmac_qpack_kpack<Element>(q_pack_lo, rhs_lo0, acc[0]);
        kkt_mmac_qpack_kpack<Element>(q_pack_lo, rhs_lo1, acc[1]);
        kkt_mmac_qpack_kpack<Element>(q_pack_lo, q_pack_lo, acc[2]);
        wait_lgkmcnt_dep<0>(rhs_hi0, rhs_hi1);
        kkt_mmac_qpack_kpack<Element>(q_pack_hi, rhs_hi0, acc[0]);
        kkt_mmac_qpack_kpack<Element>(q_pack_hi, rhs_hi1, acc[1]);
        kkt_mmac_qpack_kpack<Element>(q_pack_hi, q_pack_hi, acc[2]);
        return;
    }

    fla_u32x4 rhs_lo0 =
        kkt_read_k_stage32_nblock<Element, 0>(rhs_lds, k_stage32_lo);
    fla_u32x4 rhs_lo1 =
        kkt_read_k_stage32_nblock<Element, 1>(rhs_lds, k_stage32_lo);
    fla_u32x4 rhs_lo2 =
        kkt_read_k_stage32_nblock<Element, 2>(rhs_lds, k_stage32_lo);
    fla_u32x4 rhs_hi0 =
        kkt_read_k_stage32_nblock<Element, 0>(rhs_lds, k_stage32_hi);
    fla_u32x4 rhs_hi1 =
        kkt_read_k_stage32_nblock<Element, 1>(rhs_lds, k_stage32_hi);
    fla_u32x4 rhs_hi2 =
        kkt_read_k_stage32_nblock<Element, 2>(rhs_lds, k_stage32_hi);
    compiler_sched_barrier();

    wait_lgkmcnt_dep<3>(rhs_lo0, rhs_lo1, rhs_lo2);
    kkt_mmac_qpack_kpack<Element>(q_pack_lo, rhs_lo0, acc[0]);
    kkt_mmac_qpack_kpack<Element>(q_pack_lo, rhs_lo1, acc[1]);
    kkt_mmac_qpack_kpack<Element>(q_pack_lo, rhs_lo2, acc[2]);
    kkt_mmac_qpack_kpack<Element>(q_pack_lo, q_pack_lo, acc[3]);
    wait_lgkmcnt_dep<0>(rhs_hi0, rhs_hi1, rhs_hi2);
    kkt_mmac_qpack_kpack<Element>(q_pack_hi, rhs_hi0, acc[0]);
    kkt_mmac_qpack_kpack<Element>(q_pack_hi, rhs_hi1, acc[1]);
    kkt_mmac_qpack_kpack<Element>(q_pack_hi, rhs_hi2, acc[2]);
    kkt_mmac_qpack_kpack<Element>(q_pack_hi, q_pack_hi, acc[3]);
}

template <typename Element, bool FullRows>
__device__ __forceinline__ void kkt_compute_dot_mmac(
    const Element* __restrict__ k_tile,
    const int k_t_stride,
    Element* __restrict__ rhs_lds_tile,
    const int valid_rows,
    fla_f32x4 (&dot)[4])
{
    fla_u32x4 q_reg[4];
#pragma unroll
    for (int k_stage32 = 0; k_stage32 < 4; ++k_stage32) {
        q_reg[k_stage32] = kkt_load_k_reg_stage<Element, FullRows>(
            k_tile, k_t_stride, k_stage32, valid_rows);
    }

    kkt_prefetch_k_stage64_to_lds<Element, FullRows>(
        rhs_lds_tile, k_tile, k_t_stride, 0, valid_rows);
    compiler_sched_barrier();
    wait_vmcnt_barrier<0>();

    kkt_prefetch_k_stage64_to_lds<Element, FullRows>(
        rhs_lds_tile, k_tile, k_t_stride, 1, valid_rows);
    compiler_sched_barrier();
    kkt_mmac_qreg_k64_lower_nblocks<Element>(q_reg, rhs_lds_tile, 0, dot);
    compiler_sched_barrier();
    wait_vmcnt_lgkmcnt0_barrier<0>();
    kkt_mmac_qreg_k64_lower_nblocks<Element>(q_reg, rhs_lds_tile, 1, dot);
    compiler_sched_barrier();
    wait_lgkmcnt0_barrier();
}

template <typename ScalarT, bool SwizzleScratch, int RowBlock, int ColBlock>
__device__ __forceinline__ void kkt_store_element_v4_direct(
    ScalarT* __restrict__ A,
    const int64_t out_offset,
    const fla_f32x2 lo,
    const fla_f32x2 hi)
{
    const fla_u32x2 packed = {
        fla_pack_element_x2_bits<ScalarT>(lo),
        fla_pack_element_x2_bits<ScalarT>(hi),
    };
    *reinterpret_cast<fla_u32x2*>(A + out_offset) = packed;
}

template <typename ScalarT, bool SwizzleScratch, int RowBlock, int ColBlock>
__device__ __forceinline__ void kkt_store_inv_block_fullrows(
    const float* __restrict__ block,
    ScalarT* __restrict__ A,
    const KktSolveParams& params,
    const int lane_id,
    const int bos,
    const int chunk_start,
    const int h)
{
    const int rr = lane_id >> 2;
    const int cc = (lane_id & 3) << 2;
    const int out_token = bos + chunk_start + RowBlock * kKktBC + rr;
    const int64_t out_offset =
        (static_cast<int64_t>(out_token) * params.H + h) * params.BT +
        ColBlock * kKktBC + cc;
    kkt_store_element_v4_direct<ScalarT, SwizzleScratch, RowBlock, ColBlock>(
        A,
        out_offset,
        fla_f32x2{
            block[kkt_scratch_offset<SwizzleScratch>(rr, cc)],
            block[kkt_scratch_offset<SwizzleScratch>(rr, cc + 1)]},
        fla_f32x2{
            block[kkt_scratch_offset<SwizzleScratch>(rr, cc + 2)],
            block[kkt_scratch_offset<SwizzleScratch>(rr, cc + 3)]});
}

template <bool UseG, bool SwizzleScratch, int RowBlock, int ColBlock,
          bool DiagBlock>
__device__ __forceinline__ void kkt_store_dot_block_fullrows(
    const fla_f32x4 (&dot)[4],
    float* scratch,
    const float* __restrict__ beta_lds,
    const float* __restrict__ g_lds,
    const int rr,
    const int lane_group)
{
    const int row_in_chunk = RowBlock * kKktBC + rr;
    const float beta_r = beta_lds[row_in_chunk];
    float g_r = 0.0f;
    if constexpr (UseG) {
        g_r = g_lds[row_in_chunk];
    }

    float* block = kkt_scratch_block(
        scratch, kkt_tri_block_id(RowBlock, ColBlock));
#pragma unroll
    for (int elem = 0; elem < 4; ++elem) {
        const int cc = lane_group + elem * 4;
        float value = 0.0f;
        if constexpr (!DiagBlock) {
            value = dot[ColBlock][elem];
            if constexpr (UseG) {
                value *= fla_exp<true, false>(
                    g_r - g_lds[ColBlock * kKktBC + cc]);
            }
            value *= beta_r;
        } else {
            if (cc < rr) {
                value = dot[ColBlock][elem];
                if constexpr (UseG) {
                    value *= fla_exp<true, false>(
                        g_r - g_lds[ColBlock * kKktBC + cc]);
                }
                value *= beta_r;
            }
        }
        block[kkt_scratch_offset<SwizzleScratch>(rr, cc)] = value;
    }
}

template <bool UseG, bool SwizzleScratch>
__device__ __forceinline__ void kkt_store_dot_lower_to_scratch_fullrows(
    const fla_f32x4 (&dot)[4],
    float* scratch,
    const float* __restrict__ beta_lds,
    const float* __restrict__ g_lds)
{
    const int lane_id = static_cast<int>(threadIdx.x) & 63;
    const int lane_m = lane_id & 15;
    const int lane_group = lane_id >> 4;
    const int rb = static_cast<int>(threadIdx.x) >> 6;

    if (rb == 0) {
        kkt_store_dot_block_fullrows<UseG, SwizzleScratch, 0, 0, true>(
            dot, scratch, beta_lds, g_lds, lane_m, lane_group);
    } else if (rb == 1) {
        kkt_store_dot_block_fullrows<UseG, SwizzleScratch, 1, 0, false>(
            dot, scratch, beta_lds, g_lds, lane_m, lane_group);
        kkt_store_dot_block_fullrows<UseG, SwizzleScratch, 1, 1, true>(
            dot, scratch, beta_lds, g_lds, lane_m, lane_group);
    } else if (rb == 2) {
        kkt_store_dot_block_fullrows<UseG, SwizzleScratch, 2, 0, false>(
            dot, scratch, beta_lds, g_lds, lane_m, lane_group);
        kkt_store_dot_block_fullrows<UseG, SwizzleScratch, 2, 1, false>(
            dot, scratch, beta_lds, g_lds, lane_m, lane_group);
        kkt_store_dot_block_fullrows<UseG, SwizzleScratch, 2, 2, true>(
            dot, scratch, beta_lds, g_lds, lane_m, lane_group);
    } else {
        kkt_store_dot_block_fullrows<UseG, SwizzleScratch, 3, 0, false>(
            dot, scratch, beta_lds, g_lds, lane_m, lane_group);
        kkt_store_dot_block_fullrows<UseG, SwizzleScratch, 3, 1, false>(
            dot, scratch, beta_lds, g_lds, lane_m, lane_group);
        kkt_store_dot_block_fullrows<UseG, SwizzleScratch, 3, 2, false>(
            dot, scratch, beta_lds, g_lds, lane_m, lane_group);
        kkt_store_dot_block_fullrows<UseG, SwizzleScratch, 3, 3, true>(
            dot, scratch, beta_lds, g_lds, lane_m, lane_group);
    }
}

template <bool UseG, bool FullRows, bool SwizzleScratch>
__device__ __forceinline__ void kkt_store_dot_lower_to_scratch(
    const fla_f32x4 (&dot)[4],
    float* scratch,
    const float* __restrict__ beta_lds,
    const float* __restrict__ g_lds,
    const int valid_rows,
    const int h)
{
    (void)h;
    const int lane_id = static_cast<int>(threadIdx.x) & 63;
    const int lane_m = lane_id & 15;
    const int lane_group = lane_id >> 4;
    const int warp_id = static_cast<int>(threadIdx.x) >> 6;
    const int row_in_chunk = warp_id * kKktBC + lane_m;
    if constexpr (FullRows) {
        const int rb = warp_id;
        const int rr = lane_m;
        const float beta_r = beta_lds[row_in_chunk];
        float g_r = 0.0f;
        if constexpr (UseG) {
            g_r = g_lds[row_in_chunk];
        }

#pragma unroll
        for (int n_block = 0; n_block < 4; ++n_block) {
            if (n_block > rb) {
                continue;
            }
#pragma unroll
            for (int elem = 0; elem < 4; ++elem) {
                const int cc = lane_group + elem * 4;
                const int col_in_chunk = n_block * kKktBC + cc;
                float value = 0.0f;
                if (!(n_block == rb && cc >= rr)) {
                    value = dot[n_block][elem];
                    if constexpr (UseG) {
                        value *=
                            fla_exp<true, false>(g_r - g_lds[col_in_chunk]);
                    }
                    value *= beta_r;
                }
                kkt_scratch_block(scratch, kkt_tri_block_id(rb, n_block))
                    [kkt_scratch_offset<SwizzleScratch>(rr, cc)] = value;
            }
        }
        return;
    }

    if constexpr (!FullRows) {
        if (row_in_chunk >= valid_rows) {
            return;
        }
    }

    const float beta_r = beta_lds[row_in_chunk];
    float g_r = 0.0f;
    if constexpr (UseG) {
        g_r = g_lds[row_in_chunk];
    }
    const int rb = warp_id;
    const int rr = lane_m;
#pragma unroll
    for (int n_block = 0; n_block < 4; ++n_block) {
        if (n_block > rb) {
            continue;
        }
#pragma unroll
        for (int elem = 0; elem < 4; ++elem) {
            const int cc = lane_group + elem * 4;
            const int col_in_chunk = n_block * kKktBC + cc;
            if (col_in_chunk >= valid_rows ||
                (n_block == rb && cc >= rr)) {
                continue;
            }
            float value = dot[n_block][elem];
            if constexpr (UseG) {
                value *= fla_exp<true, false>(g_r - g_lds[col_in_chunk]);
            }
            value *= beta_r;
            kkt_scratch_block(scratch, kkt_tri_block_id(rb, n_block))
                [kkt_scratch_offset<SwizzleScratch>(rr, cc)] = value;
        }
    }
}

template <bool FullRows, bool SwizzleScratch>
__device__ __forceinline__ void kkt_solve_diag16_parallel(float* scratch, int valid_rows)
{
    const int tid = static_cast<int>(threadIdx.x);
    const int warp_id = tid >> 6;
    const int lane_id = tid & 63;
    const int lane_m = lane_id & 15;
    const int lane_group = lane_id >> 4;
    float* inv = kkt_scratch_block(scratch, kkt_tri_block_id(warp_id, warp_id));

    if constexpr (FullRows) {
        if (lane_group == 0) {
            float col[kKktBC];
#pragma unroll
            for (int row = 0; row < kKktBC; ++row) {
                col[row] = -inv[kkt_scratch_offset<SwizzleScratch>(row, lane_m)];
            }

#pragma unroll
            for (int row = 2; row < kKktBC; ++row) {
                float acc = col[row];
                const uint32_t row_bits = ck_tile::bit_cast<uint32_t>(col[row]);
#pragma unroll
                for (int m = 0; m < row; ++m) {
                    const float row_m = ck_tile::bit_cast<float>(
                        fla_ds_bpermute_u32(m << 2, row_bits));
                    acc += row_m * col[m];
                }
                col[row] = acc;
            }

            col[lane_m] += 1.0f;

#pragma unroll
            for (int row = 0; row < kKktBC; ++row) {
                inv[kkt_scratch_offset<SwizzleScratch>(row, lane_m)] = col[row];
            }
        }
        __syncthreads();
        return;
    }

    const int block_valid_rows =
        FullRows ? kKktBC : valid_rows - warp_id * kKktBC;

    for (int element = lane_id; element < kKktBC * kKktBC; element += 64) {
        const int offset = kkt_scratch_linear_offset<SwizzleScratch>(element);
        inv[offset] = -inv[offset];
    }
    __builtin_amdgcn_wave_barrier();

#pragma unroll
    for (int i = 2; i < kKktBC; ++i) {
        if (lane_group == 0 && (FullRows || i < block_valid_rows)) {
            const float row_c =
                lane_m < i ? inv[kkt_scratch_offset<SwizzleScratch>(i, lane_m)] : 0.0f;
            float acc = row_c;
            const uint32_t row_bits = ck_tile::bit_cast<uint32_t>(row_c);
#pragma unroll
            for (int m = 0; m < i; ++m) {
                const float row_m = ck_tile::bit_cast<float>(
                    fla_ds_bpermute_u32(m << 2, row_bits));
                acc += row_m * inv[kkt_scratch_offset<SwizzleScratch>(m, lane_m)];
            }
            inv[kkt_scratch_offset<SwizzleScratch>(i, lane_m)] = acc;
        }
        __builtin_amdgcn_wave_barrier();
    }

    if (lane_group == 0) {
        inv[kkt_scratch_offset<SwizzleScratch>(lane_m, lane_m)] += 1.0f;
    }
    __syncthreads();
}

template <bool SwizzleScratch>
__device__ __forceinline__ void kkt_matmul16_element(
    const float* __restrict__ a,
    const float* __restrict__ b,
    float* __restrict__ out,
    int tid)
{
    const int r = tid / kKktBC;
    const int c = tid - r * kKktBC;
    float acc = 0.0f;
#pragma unroll
    for (int m = 0; m < kKktBC; ++m) {
        acc +=
            a[kkt_scratch_offset<SwizzleScratch>(r, m)] *
            b[kkt_scratch_offset<SwizzleScratch>(m, c)];
    }
    out[kkt_scratch_linear_offset<SwizzleScratch>(tid)] = acc;
}

template <bool SwizzleScratch>
__device__ __forceinline__ void kkt_neg_matmul16_element(
    const float* __restrict__ a,
    const float* __restrict__ b,
    float* __restrict__ out,
    int tid)
{
    const int r = tid / kKktBC;
    const int c = tid - r * kKktBC;
    float acc = 0.0f;
#pragma unroll
    for (int m = 0; m < kKktBC; ++m) {
        acc +=
            a[kkt_scratch_offset<SwizzleScratch>(r, m)] *
            b[kkt_scratch_offset<SwizzleScratch>(m, c)];
    }
    out[kkt_scratch_linear_offset<SwizzleScratch>(tid)] = -acc;
}

template <bool SwizzleScratch>
__device__ __forceinline__ void kkt_neg_matmul16_left_product_element_scalar(
    const float* __restrict__ a,
    const float* __restrict__ b,
    const float* __restrict__ c,
    float* __restrict__ out,
    int tid)
{
    const int r = tid / kKktBC;
    const int out_c = tid - r * kKktBC;
    float acc = 0.0f;
#pragma unroll
    for (int k = 0; k < kKktBC; ++k) {
        float mid = 0.0f;
#pragma unroll
        for (int m = 0; m < kKktBC; ++m) {
            mid +=
                a[kkt_scratch_offset<SwizzleScratch>(r, m)] *
                b[kkt_scratch_offset<SwizzleScratch>(m, k)];
        }
        acc += mid * c[kkt_scratch_offset<SwizzleScratch>(k, out_c)];
    }
    out[kkt_scratch_linear_offset<SwizzleScratch>(tid)] = -acc;
}

template <bool SwizzleScratch>
__device__ __forceinline__ void kkt_matmul16_sum2_element_scalar(
    const float* __restrict__ a0,
    const float* __restrict__ b0,
    const float* __restrict__ a1,
    const float* __restrict__ b1,
    float* __restrict__ out,
    int tid)
{
    const int r = tid / kKktBC;
    const int c = tid - r * kKktBC;
    float acc = 0.0f;
#pragma unroll
    for (int m = 0; m < kKktBC; ++m) {
        acc +=
            a0[kkt_scratch_offset<SwizzleScratch>(r, m)] *
            b0[kkt_scratch_offset<SwizzleScratch>(m, c)];
        acc +=
            a1[kkt_scratch_offset<SwizzleScratch>(r, m)] *
            b1[kkt_scratch_offset<SwizzleScratch>(m, c)];
    }
    out[kkt_scratch_linear_offset<SwizzleScratch>(tid)] = acc;
}

template <bool SwizzleScratch>
__device__ __forceinline__ void kkt_matmul16_sum3_element_scalar(
    const float* __restrict__ a0,
    const float* __restrict__ b0,
    const float* __restrict__ a1,
    const float* __restrict__ b1,
    const float* __restrict__ a2,
    const float* __restrict__ b2,
    float* __restrict__ out,
    int tid)
{
    const int r = tid / kKktBC;
    const int c = tid - r * kKktBC;
    float acc = 0.0f;
#pragma unroll
    for (int m = 0; m < kKktBC; ++m) {
        acc +=
            a0[kkt_scratch_offset<SwizzleScratch>(r, m)] *
            b0[kkt_scratch_offset<SwizzleScratch>(m, c)];
        acc +=
            a1[kkt_scratch_offset<SwizzleScratch>(r, m)] *
            b1[kkt_scratch_offset<SwizzleScratch>(m, c)];
        acc +=
            a2[kkt_scratch_offset<SwizzleScratch>(r, m)] *
            b2[kkt_scratch_offset<SwizzleScratch>(m, c)];
    }
    out[kkt_scratch_linear_offset<SwizzleScratch>(tid)] = acc;
}

__device__ __forceinline__ fla_f32x4 kkt_mmac_f32_16x16x8(
    const fla_f32x2 a, const fla_f32x2 b, const fla_f32x4 c)
{
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    return __builtin_hcu_mmac_16x16x8_f32(a, b, c);
#else
    (void)a;
    (void)b;
    return c;
#endif
}

template <bool SwizzleScratch>
__device__ __forceinline__ void kkt_mmac16_accumulate(
    const float* __restrict__ a,
    const float* __restrict__ b,
    int row,
    int k_group,
    fla_f32x4& acc)
{
#pragma unroll
    for (int base_k = 0; base_k < kKktBC; base_k += 8) {
        const int k0 = base_k + k_group;
        const int k1 = k0 + 4;
        const fla_f32x2 a_pair = {
            a[kkt_scratch_offset<SwizzleScratch>(row, k0)],
            a[kkt_scratch_offset<SwizzleScratch>(row, k1)]};
        const fla_f32x2 b_pair = {
            b[kkt_scratch_offset<SwizzleScratch>(k0, row)],
            b[kkt_scratch_offset<SwizzleScratch>(k1, row)]};
        acc = kkt_mmac_f32_16x16x8(a_pair, b_pair, acc);
    }
}

template <int WorkerWave = 0, bool SwizzleScratch = false>
__device__ __forceinline__ void kkt_mmac16_element(
    const float* __restrict__ a,
    const float* __restrict__ b,
    float* __restrict__ out,
    int tid)
{
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    if ((tid >> 6) != WorkerWave) {
        return;
    }
    const int lane = tid & 63;
    const int row = lane & 15;
    const int k_group = lane >> 4;
    fla_f32x4 acc = {0.0f, 0.0f, 0.0f, 0.0f};
    kkt_mmac16_accumulate<SwizzleScratch>(a, b, row, k_group, acc);
#pragma unroll
    for (int slot = 0; slot < 4; ++slot) {
        out[kkt_scratch_offset<SwizzleScratch>(row, k_group + slot * 4)] = acc[slot];
    }
#else
    kkt_matmul16_element<SwizzleScratch>(a, b, out, tid);
#endif
}

template <int WorkerWave = 0, bool SwizzleScratch = false>
__device__ __forceinline__ void kkt_neg_mmac16_element(
    const float* __restrict__ a,
    const float* __restrict__ b,
    float* __restrict__ out,
    int tid)
{
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    if ((tid >> 6) != WorkerWave) {
        return;
    }
    const int lane = tid & 63;
    const int row = lane & 15;
    const int k_group = lane >> 4;
    fla_f32x4 acc = {0.0f, 0.0f, 0.0f, 0.0f};
    kkt_mmac16_accumulate<SwizzleScratch>(a, b, row, k_group, acc);
#pragma unroll
    for (int slot = 0; slot < 4; ++slot) {
        out[kkt_scratch_offset<SwizzleScratch>(row, k_group + slot * 4)] = -acc[slot];
    }
#else
    kkt_neg_matmul16_element<SwizzleScratch>(a, b, out, tid);
#endif
}

template <int WorkerWave = 0, bool SwizzleScratch = false>
__device__ __forceinline__ void kkt_neg_mmac16_left_product_element(
    const float* a,
    const float* b,
    const float* c,
    float* out,
    int tid)
{
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    if ((tid >> 6) != WorkerWave) {
        return;
    }
    const int lane = tid & 63;
    const int row = lane & 15;
    const int k_group = lane >> 4;
    fla_f32x4 mid = {0.0f, 0.0f, 0.0f, 0.0f};
    fla_f32x4 acc = {0.0f, 0.0f, 0.0f, 0.0f};
    kkt_mmac16_accumulate<SwizzleScratch>(a, b, row, k_group, mid);

#pragma unroll
    for (int base_k = 0; base_k < kKktBC; base_k += 8) {
        const int k0 = base_k + k_group;
        const int k1 = k0 + 4;
        const int slot0 = base_k >> 2;
        const int slot1 = slot0 + 1;
        const fla_f32x2 a_pair = {mid[slot0], mid[slot1]};
        const fla_f32x2 b_pair = {
            c[kkt_scratch_offset<SwizzleScratch>(k0, row)],
            c[kkt_scratch_offset<SwizzleScratch>(k1, row)]};
        acc = kkt_mmac_f32_16x16x8(a_pair, b_pair, acc);
    }

#pragma unroll
    for (int slot = 0; slot < 4; ++slot) {
        out[kkt_scratch_offset<SwizzleScratch>(row, k_group + slot * 4)] = -acc[slot];
    }
#else
    const int r = tid / kKktBC;
    const int out_c = tid - r * kKktBC;
    float acc = 0.0f;
#pragma unroll
    for (int k = 0; k < kKktBC; ++k) {
        float mid = 0.0f;
#pragma unroll
        for (int m = 0; m < kKktBC; ++m) {
            mid +=
                a[kkt_scratch_offset<SwizzleScratch>(r, m)] *
                b[kkt_scratch_offset<SwizzleScratch>(m, k)];
        }
        acc += mid * c[kkt_scratch_offset<SwizzleScratch>(k, out_c)];
    }
    out[kkt_scratch_linear_offset<SwizzleScratch>(tid)] = -acc;
#endif
}

template <int WorkerWave = 0, bool SwizzleScratch = false>
__device__ __forceinline__ void kkt_mmac16_sum2_element(
    const float* __restrict__ a0,
    const float* __restrict__ b0,
    const float* __restrict__ a1,
    const float* __restrict__ b1,
    float* __restrict__ out,
    int tid)
{
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    if ((tid >> 6) != WorkerWave) {
        return;
    }
    const int lane = tid & 63;
    const int row = lane & 15;
    const int k_group = lane >> 4;
    fla_f32x4 acc = {0.0f, 0.0f, 0.0f, 0.0f};
    kkt_mmac16_accumulate<SwizzleScratch>(a0, b0, row, k_group, acc);
    kkt_mmac16_accumulate<SwizzleScratch>(a1, b1, row, k_group, acc);
#pragma unroll
    for (int slot = 0; slot < 4; ++slot) {
        out[kkt_scratch_offset<SwizzleScratch>(row, k_group + slot * 4)] = acc[slot];
    }
#else
    const int r = tid / kKktBC;
    const int c = tid - r * kKktBC;
    float acc = 0.0f;
#pragma unroll
    for (int m = 0; m < kKktBC; ++m) {
        acc +=
            a0[kkt_scratch_offset<SwizzleScratch>(r, m)] *
            b0[kkt_scratch_offset<SwizzleScratch>(m, c)];
        acc +=
            a1[kkt_scratch_offset<SwizzleScratch>(r, m)] *
            b1[kkt_scratch_offset<SwizzleScratch>(m, c)];
    }
    out[kkt_scratch_linear_offset<SwizzleScratch>(tid)] = acc;
#endif
}

template <int WorkerWave = 0, bool SwizzleScratch = false>
__device__ __forceinline__ void kkt_mmac16_sum3_element(
    const float* __restrict__ a0,
    const float* __restrict__ b0,
    const float* __restrict__ a1,
    const float* __restrict__ b1,
    const float* __restrict__ a2,
    const float* __restrict__ b2,
    float* __restrict__ out,
    int tid)
{
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    if ((tid >> 6) != WorkerWave) {
        return;
    }
    const int lane = tid & 63;
    const int row = lane & 15;
    const int k_group = lane >> 4;
    fla_f32x4 acc = {0.0f, 0.0f, 0.0f, 0.0f};
    kkt_mmac16_accumulate<SwizzleScratch>(a0, b0, row, k_group, acc);
    kkt_mmac16_accumulate<SwizzleScratch>(a1, b1, row, k_group, acc);
    kkt_mmac16_accumulate<SwizzleScratch>(a2, b2, row, k_group, acc);
#pragma unroll
    for (int slot = 0; slot < 4; ++slot) {
        out[kkt_scratch_offset<SwizzleScratch>(row, k_group + slot * 4)] = acc[slot];
    }
#else
    const int r = tid / kKktBC;
    const int c = tid - r * kKktBC;
    float acc = 0.0f;
#pragma unroll
    for (int m = 0; m < kKktBC; ++m) {
        acc +=
            a0[kkt_scratch_offset<SwizzleScratch>(r, m)] *
            b0[kkt_scratch_offset<SwizzleScratch>(m, c)];
        acc +=
            a1[kkt_scratch_offset<SwizzleScratch>(r, m)] *
            b1[kkt_scratch_offset<SwizzleScratch>(m, c)];
        acc +=
            a2[kkt_scratch_offset<SwizzleScratch>(r, m)] *
            b2[kkt_scratch_offset<SwizzleScratch>(m, c)];
    }
    out[kkt_scratch_linear_offset<SwizzleScratch>(tid)] = acc;
#endif
}

// Used with empty output allocation: the solved A is lower triangular, so the
// strict upper-triangular blocks must be written explicitly.
template <typename ScalarT>
__device__ __forceinline__ void kkt_store_upper_zero_blocks(
    ScalarT* __restrict__ A,
    const KktSolveParams& params,
    const int tid,
    const int valid_rows,
    const int bos,
    const int chunk_start,
    const int h)
{
    const int warp_id = tid >> 6;
    const int lane_id = tid & 63;

#pragma unroll
    for (int upper_id = warp_id; upper_id < 6; upper_id += 4) {
        const int rb = upper_id < 3 ? 0 : (upper_id < 5 ? 1 : 2);
        const int cb = upper_id < 3 ? upper_id + 1 :
            (upper_id < 5 ? upper_id - 1 : 3);
        const int row_block_start = rb * kKktBC;
        const int col_block_start = cb * kKktBC;
        const int rr = lane_id >> 2;
        const int cc = (lane_id & 3) << 2;
        const int row_in_chunk = row_block_start + rr;
        const int col_in_chunk = col_block_start + cc;
        if (row_in_chunk >= valid_rows) {
            continue;
        }
        const int out_token = bos + chunk_start + row_in_chunk;
        const int64_t out_offset =
            (static_cast<int64_t>(out_token) * params.H + h) * params.BT +
            col_in_chunk;
        fla_buffer_store_element_v4_vgpr<ScalarT>(
            A,
            static_cast<int32_t>(
                out_offset * static_cast<int64_t>(sizeof(ScalarT))),
            fla_f32x2{0.0f, 0.0f},
            fla_f32x2{0.0f, 0.0f});
    }
}

template <typename ScalarT, int WorkerWave = 3>
__device__ __forceinline__ void kkt_store_upper_zero_blocks_fullrows_wave(
    ScalarT* __restrict__ A,
    const KktSolveParams& params,
    const int tid,
    const int bos,
    const int chunk_start,
    const int h)
{
    const int warp_id = tid >> 6;
    if (warp_id != WorkerWave) {
        return;
    }

    const int lane_id = tid & 63;

#pragma unroll
    for (int upper_id = 0; upper_id < 6; ++upper_id) {
        const int rb = upper_id < 3 ? 0 : (upper_id < 5 ? 1 : 2);
        const int cb = upper_id < 3 ? upper_id + 1 :
            (upper_id < 5 ? upper_id - 1 : 3);
        const int row_block_start = rb * kKktBC;
        const int col_block_start = cb * kKktBC;
        const int rr = lane_id >> 2;
        const int cc = (lane_id & 3) << 2;
        const int out_token = bos + chunk_start + row_block_start + rr;
        const int out_offset =
            (out_token * params.H + h) * params.BT + col_block_start + cc;
        fla_buffer_store_element_v4_vgpr<ScalarT>(
            A,
            static_cast<int32_t>(out_offset * static_cast<int>(sizeof(ScalarT))),
            fla_f32x2{0.0f, 0.0f},
            fla_f32x2{0.0f, 0.0f});
    }
}

template <typename BetaT, bool UseG, bool FullRows, bool SwizzleScratch>
__device__ __forceinline__ void kkt_fill_scratch_from_mfma_dot(
    const fla_f32x4 (&dot)[4],
    float* scratch,
    const float* __restrict__ g,
    const BetaT* __restrict__ beta,
    const KktSolveParams& params,
    const int tid,
    const int valid_rows,
    const int bos,
    const int chunk_start,
    const int h)
{
    if constexpr (!FullRows) {
        for (int i = tid; i < kKktScratchElements; i += blockDim.x) {
            scratch[i] = 0.0f;
        }
    }
    float* beta_lds = scratch + kKktScaleOffset;
    float* g_lds = beta_lds + kKktMaxBT;
    for (int row = tid; row < kKktMaxBT; row += blockDim.x) {
        if constexpr (FullRows) {
            const int token = bos + chunk_start + row;
            const int row_h_offset = token * params.H + h;
            float g_value = 0.0f;
            if constexpr (UseG) {
                g_value = g[row_h_offset];
            }
            beta_lds[row] = kkt_to_float(beta[row_h_offset]);
            if constexpr (UseG) {
                g_lds[row] = g_value;
            }
        } else if (row < valid_rows) {
            const int token = bos + chunk_start + row;
            float g_value = 0.0f;
            if constexpr (UseG) {
                g_value = g[static_cast<int64_t>(token) * params.H + h];
            }
            beta_lds[row] =
                kkt_to_float(beta[static_cast<int64_t>(token) * params.H + h]);
            if constexpr (UseG) {
                g_lds[row] = g_value;
            }
        } else {
            beta_lds[row] = 0.0f;
            if constexpr (UseG) {
                g_lds[row] = 0.0f;
            }
        }
    }
    __syncthreads();

    kkt_store_dot_lower_to_scratch<UseG, FullRows, SwizzleScratch>(
        dot, scratch, beta_lds, g_lds, valid_rows, h);
}

template <typename BetaT, bool UseG, bool SwizzleScratch>
__device__ __forceinline__ void kkt_fill_scratch_single_block_from_mfma_dot(
    const fla_f32x4 (&dot)[4],
    float* scratch,
    const float* __restrict__ g,
    const BetaT* __restrict__ beta,
    const KktSolveParams& params,
    const int tid,
    const int valid_rows,
    const int bos,
    const int chunk_start,
    const int h)
{
    float* ai00 = kkt_scratch_block(scratch, kkt_tri_block_id(0, 0));
    for (int i = tid; i < kKktScratchBlockElements; i += blockDim.x) {
        ai00[i] = 0.0f;
    }

    float* beta_lds = scratch + kKktScaleOffset;
    float* g_lds = beta_lds + kKktMaxBT;
    if (tid < valid_rows) {
        const int token = bos + chunk_start + tid;
        const int64_t row_h_offset =
            static_cast<int64_t>(token) * params.H + h;
        beta_lds[tid] = kkt_to_float(beta[row_h_offset]);
        if constexpr (UseG) {
            g_lds[tid] = g[row_h_offset];
        }
    }
    __syncthreads();

    kkt_store_dot_lower_to_scratch<UseG, false, SwizzleScratch>(
        dot, scratch, beta_lds, g_lds, valid_rows, h);
}

template <typename BetaT, bool UseG, bool SwizzleScratch>
__device__ __forceinline__ void kkt_fill_scratch_from_mfma_dot_fullrows_fast(
    const fla_f32x4 (&dot)[4],
    float* scratch,
    const float* __restrict__ g,
    const BetaT* __restrict__ beta,
    const KktSolveParams& params,
    const int tid,
    const int bos,
    const int chunk_start,
    const int h)
{
    float* beta_lds = scratch + kKktScaleOffset;
    float* g_lds = beta_lds + kKktMaxBT;
    for (int row = tid; row < kKktMaxBT; row += blockDim.x) {
        const int token = bos + chunk_start + row;
        const int row_h_offset = token * params.H + h;
        beta_lds[row] = kkt_to_float(beta[row_h_offset]);
        if constexpr (UseG) {
            g_lds[row] = g[row_h_offset];
        }
    }
    __syncthreads();

    kkt_store_dot_lower_to_scratch_fullrows<UseG, SwizzleScratch>(
        dot, scratch, beta_lds, UseG ? g_lds : nullptr);
}

template <typename BetaT, bool UseG>
__device__ __forceinline__ void kkt_preload_group_scales_fullrows(
    float* __restrict__ scratch,
    const float* __restrict__ g,
    const BetaT* __restrict__ beta,
    const KktSolveParams& params,
    const int tid,
    const int bos,
    const int chunk_start,
    const int h_begin,
    const int heads_per_k)
{
    float* beta_lds = scratch + kKktScaleOffset;
    float* g_lds = beta_lds + kKktMaxBT * kKktScaleHeadCap;
    if (heads_per_k == 2) {
        for (int row = tid; row < kKktMaxBT; row += blockDim.x) {
            const int token = bos + chunk_start + row;
            const int row_h_offset = token * params.H + h_begin;
            if constexpr (std::is_same_v<BetaT, float>) {
                const fla_f32x2 beta_pair =
                    *reinterpret_cast<const fla_f32x2*>(beta + row_h_offset);
                beta_lds[row] = beta_pair[0];
                beta_lds[kKktMaxBT + row] = beta_pair[1];
            } else {
                beta_lds[row] = kkt_to_float(beta[row_h_offset]);
                beta_lds[kKktMaxBT + row] =
                    kkt_to_float(beta[row_h_offset + 1]);
            }
            if constexpr (UseG) {
                const fla_f32x2 g_pair =
                    *reinterpret_cast<const fla_f32x2*>(g + row_h_offset);
                g_lds[row] = g_pair[0];
                g_lds[kKktMaxBT + row] = g_pair[1];
            }
        }
        __syncthreads();
        return;
    }
    const int total_rows = kKktMaxBT * heads_per_k;
    for (int idx = tid; idx < total_rows; idx += blockDim.x) {
        const int head_slot = idx >> 6;
        const int row = idx & (kKktMaxBT - 1);
        const int h = h_begin + head_slot;
        const int token = bos + chunk_start + row;
        const int row_h_offset = token * params.H + h;
        beta_lds[head_slot * kKktMaxBT + row] =
            kkt_to_float(beta[row_h_offset]);
        if constexpr (UseG) {
            g_lds[head_slot * kKktMaxBT + row] = g[row_h_offset];
        }
    }
    __syncthreads();
}

template <typename ScalarT, typename BetaT, bool UseG, bool SwizzleScratch>
__device__ __forceinline__ void kkt_fill_scratch_scalar(
    float* scratch,
    const ScalarT* __restrict__ k,
    const float* __restrict__ g,
    const BetaT* __restrict__ beta,
    const KktSolveParams& params,
    const int tid,
    const int valid_rows,
    const int bos,
    const int chunk_start,
    const int h,
    const int kg_head)
{
    for (int i = tid; i < kKktScratchElements; i += blockDim.x) {
        scratch[i] = 0.0f;
    }
    __syncthreads();

    for (int rb = 0; rb < 4; ++rb) {
        const int row_block_start = rb * kKktBC;
        if (row_block_start >= params.BT || row_block_start >= valid_rows) {
            continue;
        }
        for (int cb = 0; cb <= rb; ++cb) {
            const int col_block_start = cb * kKktBC;
            if (col_block_start >= params.BT || col_block_start >= valid_rows) {
                continue;
            }

            float* out = kkt_scratch_block(scratch, kkt_tri_block_id(rb, cb));
            for (int element = tid; element < kKktBC * kKktBC; element += blockDim.x) {
                const int rr = element / kKktBC;
                const int cc = element - rr * kKktBC;
                const int row_in_chunk = row_block_start + rr;
                if (row_in_chunk >= params.BT || row_in_chunk >= valid_rows) {
                    continue;
                }
                const int row_token = bos + chunk_start + row_in_chunk;
                const float beta_r =
                    kkt_to_float(beta[static_cast<int64_t>(row_token) * params.H + h]);
                float g_r = 0.0f;
                if constexpr (UseG) {
                    g_r = g[static_cast<int64_t>(row_token) * params.H + h];
                }

                const int col_in_chunk = col_block_start + cc;
                if (col_in_chunk >= params.BT || col_in_chunk >= valid_rows) {
                    continue;
                }
                if (rb == cb && cc >= rr) {
                    continue;
                }

                const int col_token = bos + chunk_start + col_in_chunk;
                float dot = 0.0f;
                for (int kk = 0; kk < params.K; ++kk) {
                    const int64_t row_k =
                        (static_cast<int64_t>(row_token) * params.Hg + kg_head) * params.K + kk;
                    const int64_t col_k =
                        (static_cast<int64_t>(col_token) * params.Hg + kg_head) * params.K + kk;
                    dot += kkt_to_float(k[row_k]) * kkt_to_float(k[col_k]);
                }

                if constexpr (UseG) {
                    const float g_c = g[static_cast<int64_t>(col_token) * params.H + h];
                    const float diff = g_r - g_c;
                    dot *= fla_exp<true, false>(diff);
                }
                out[kkt_scratch_linear_offset<SwizzleScratch>(element)] = dot * beta_r;
            }
        }
    }
}

template <typename ScalarT, bool FullRows, bool SwizzleScratch>
__device__ __forceinline__ void kkt_solve_merge_store(
    float* __restrict__ scratch,
    ScalarT* __restrict__ A,
    const KktSolveParams& params,
    const int tid,
    const int valid_rows,
    const int bos,
    const int chunk_start,
    const int h)
{
    if constexpr (FullRows) {
        __builtin_amdgcn_wave_barrier();
    } else {
        __syncthreads();
    }

    const int id00 = kkt_tri_block_id(0, 0);
    const int id10 = kkt_tri_block_id(1, 0);
    const int id11 = kkt_tri_block_id(1, 1);
    const int id20 = kkt_tri_block_id(2, 0);
    const int id21 = kkt_tri_block_id(2, 1);
    const int id22 = kkt_tri_block_id(2, 2);
    const int id30 = kkt_tri_block_id(3, 0);
    const int id31 = kkt_tri_block_id(3, 1);
    const int id32 = kkt_tri_block_id(3, 2);
    const int id33 = kkt_tri_block_id(3, 3);

    float* ai00 = kkt_scratch_block(scratch, id00);
    float* ai10 = kkt_scratch_block(scratch, id10);
    float* ai11 = kkt_scratch_block(scratch, id11);
    float* ai20 = kkt_scratch_block(scratch, id20);
    float* ai21 = kkt_scratch_block(scratch, id21);
    float* ai22 = kkt_scratch_block(scratch, id22);
    float* ai30 = kkt_scratch_block(scratch, id30);
    float* ai31 = kkt_scratch_block(scratch, id31);
    float* ai32 = kkt_scratch_block(scratch, id32);
    float* ai33 = kkt_scratch_block(scratch, id33);
    float* tmp0 = kkt_scratch_block(scratch, kKktTemp0Block);
    float* tmp1 = kkt_scratch_block(scratch, kKktTemp1Block);
    float* tmp2 = kkt_scratch_block(scratch, kKktTemp2Block);
    using StoreElement = ScalarT;
    auto* __restrict__ A_store = reinterpret_cast<StoreElement*>(A);
    const int warp_id = tid >> 6;
    const int lane_id = tid & 63;
    constexpr bool EarlyDiagStore =
        std::is_same_v<ScalarT, ck_tile::bf16_t>;

    kkt_solve_diag16_parallel<FullRows, SwizzleScratch>(scratch, valid_rows);

    if constexpr (FullRows) {
        kkt_store_upper_zero_blocks_fullrows_wave<ScalarT>(
            A, params, tid, bos, chunk_start, h);

        if constexpr (EarlyDiagStore) {
            if (warp_id == 2) {
                kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 0, 0>(
                    ai00, A_store, params, lane_id, bos, chunk_start, h);
                kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 1, 1>(
                    ai11, A_store, params, lane_id, bos, chunk_start, h);
            } else if (warp_id == 3) {
                kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 2, 2>(
                    ai22, A_store, params, lane_id, bos, chunk_start, h);
                kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 3, 3>(
                    ai33, A_store, params, lane_id, bos, chunk_start, h);
            }
        }

        kkt_neg_mmac16_left_product_element<0, SwizzleScratch>(
            ai11, ai10, ai00, ai10, tid);
        __builtin_amdgcn_wave_barrier();

        kkt_mmac16_sum2_element<0, SwizzleScratch>(
            ai20, ai00, ai21, ai10, tmp0, tid);
        kkt_mmac16_element<1, SwizzleScratch>(ai22, ai21, tmp1, tid);
        __builtin_amdgcn_wave_barrier();
        kkt_neg_mmac16_element<0, SwizzleScratch>(ai22, tmp0, ai20, tid);
        kkt_neg_mmac16_element<1, SwizzleScratch>(tmp1, ai11, ai21, tid);
        __builtin_amdgcn_wave_barrier();

        kkt_mmac16_sum3_element<0, SwizzleScratch>(
            ai30, ai00, ai31, ai10, ai32, ai20, tmp0, tid);
        kkt_mmac16_sum2_element<1, SwizzleScratch>(
            ai31, ai11, ai32, ai21, tmp1, tid);
        kkt_mmac16_element<2, SwizzleScratch>(ai33, ai32, tmp2, tid);
        __builtin_amdgcn_wave_barrier();
        kkt_neg_mmac16_element<0, SwizzleScratch>(ai33, tmp0, ai30, tid);
        kkt_neg_mmac16_element<1, SwizzleScratch>(ai33, tmp1, ai31, tid);
        kkt_neg_mmac16_element<2, SwizzleScratch>(tmp2, ai22, ai32, tid);
        __syncthreads();
    } else {
        kkt_neg_matmul16_left_product_element_scalar<SwizzleScratch>(
            ai11, ai10, ai00, ai10, tid);
        __syncthreads();

        kkt_matmul16_sum2_element_scalar<SwizzleScratch>(
            ai20, ai00, ai21, ai10, tmp0, tid);
        kkt_matmul16_element<SwizzleScratch>(ai22, ai21, tmp1, tid);
        __syncthreads();
        kkt_neg_matmul16_element<SwizzleScratch>(ai22, tmp0, ai20, tid);
        kkt_neg_matmul16_element<SwizzleScratch>(tmp1, ai11, ai21, tid);
        __syncthreads();

        kkt_matmul16_sum3_element_scalar<SwizzleScratch>(
            ai30, ai00, ai31, ai10, ai32, ai20, tmp0, tid);
        kkt_matmul16_sum2_element_scalar<SwizzleScratch>(
            ai31, ai11, ai32, ai21, tmp1, tid);
        kkt_matmul16_element<SwizzleScratch>(ai33, ai32, tmp2, tid);
        __syncthreads();
        kkt_neg_matmul16_element<SwizzleScratch>(ai33, tmp0, ai30, tid);
        kkt_neg_matmul16_element<SwizzleScratch>(ai33, tmp1, ai31, tid);
        kkt_neg_matmul16_element<SwizzleScratch>(tmp2, ai22, ai32, tid);
        __syncthreads();
    }

    const float* inv_blocks[kKktNumTriBlocks] = {
        ai00, ai10, ai11, ai20, ai21, ai22, ai30, ai31, ai32, ai33};

    if constexpr (FullRows) {
        if (warp_id == 0) {
            if constexpr (!EarlyDiagStore) {
                kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 0, 0>(
                    ai00, A_store, params, lane_id, bos, chunk_start, h);
            }
            kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 2, 1>(
                ai21, A_store, params, lane_id, bos, chunk_start, h);
            kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 3, 2>(
                ai32, A_store, params, lane_id, bos, chunk_start, h);
        } else if (warp_id == 1) {
            kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 1, 0>(
                ai10, A_store, params, lane_id, bos, chunk_start, h);
            if constexpr (!EarlyDiagStore) {
                kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 2, 2>(
                    ai22, A_store, params, lane_id, bos, chunk_start, h);
                kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 3, 3>(
                    ai33, A_store, params, lane_id, bos, chunk_start, h);
            }
        } else if (warp_id == 2) {
            if constexpr (!EarlyDiagStore) {
                kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 1, 1>(
                    ai11, A_store, params, lane_id, bos, chunk_start, h);
            }
            kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 3, 0>(
                ai30, A_store, params, lane_id, bos, chunk_start, h);
        } else {
            kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 2, 0>(
                ai20, A_store, params, lane_id, bos, chunk_start, h);
            kkt_store_inv_block_fullrows<StoreElement, SwizzleScratch, 3, 1>(
                ai31, A_store, params, lane_id, bos, chunk_start, h);
        }
        return;
    }

    for (int rb = 0; rb < 4; ++rb) {
        const int row_block_start = rb * kKktBC;
        if (row_block_start >= params.BT || row_block_start >= valid_rows) {
            continue;
        }
        for (int cb = 0; cb <= rb; ++cb) {
            const int col_block_start = cb * kKktBC;
            if (col_block_start >= params.BT) {
                continue;
            }
            const float* block = inv_blocks[kkt_tri_block_id(rb, cb)];
            for (int element = tid; element < kKktBC * kKktBC; element += blockDim.x) {
                const int rr = element / kKktBC;
                const int cc = element - rr * kKktBC;
                const int row_in_chunk = row_block_start + rr;
                if (row_in_chunk >= params.BT || row_in_chunk >= valid_rows) {
                    continue;
                }
                const int out_token = bos + chunk_start + row_in_chunk;
                const int64_t out_base =
                    (static_cast<int64_t>(out_token) * params.H + h) * params.BT;
                const int col_in_chunk = col_block_start + cc;
                if (col_in_chunk >= params.BT) {
                    continue;
                }
                A[out_base + col_in_chunk] =
                    ck_tile::type_convert<ScalarT>(
                        block[kkt_scratch_linear_offset<SwizzleScratch>(element)]);
            }
        }
    }

    if (params.K == kKktBK && params.BT == kKktMaxBT) {
        kkt_store_upper_zero_blocks<ScalarT>(
            A, params, tid, valid_rows, bos, chunk_start, h);
    }
}

template <typename ScalarT, bool SwizzleScratch>
__device__ __forceinline__ void kkt_solve_store_single_block(
    float* __restrict__ scratch,
    ScalarT* __restrict__ A,
    const KktSolveParams& params,
    const int tid,
    const int valid_rows,
    const int bos,
    const int chunk_start,
    const int h)
{
    __syncthreads();

    float* ai00 = kkt_scratch_block(scratch, kkt_tri_block_id(0, 0));
    const int lane_id = tid & 63;
    const int lane_m = lane_id & 15;
    const int lane_group = lane_id >> 4;

    if (tid < 64) {
        for (int element = lane_id; element < kKktBC * kKktBC; element += 64) {
            const int offset =
                kkt_scratch_linear_offset<SwizzleScratch>(element);
            ai00[offset] = -ai00[offset];
        }
        __builtin_amdgcn_wave_barrier();

#pragma unroll
        for (int i = 2; i < kKktBC; ++i) {
            if (lane_group == 0 && i < valid_rows) {
                const float row_c =
                    lane_m < i ? ai00[kkt_scratch_offset<SwizzleScratch>(i, lane_m)] : 0.0f;
                float acc = row_c;
                const uint32_t row_bits = ck_tile::bit_cast<uint32_t>(row_c);
#pragma unroll
                for (int m = 0; m < i; ++m) {
                    const float row_m = ck_tile::bit_cast<float>(
                        fla_ds_bpermute_u32(m << 2, row_bits));
                    acc += row_m *
                        ai00[kkt_scratch_offset<SwizzleScratch>(m, lane_m)];
                }
                ai00[kkt_scratch_offset<SwizzleScratch>(i, lane_m)] = acc;
            }
            __builtin_amdgcn_wave_barrier();
        }

        if (lane_group == 0) {
            ai00[kkt_scratch_offset<SwizzleScratch>(lane_m, lane_m)] += 1.0f;
        }
        __builtin_amdgcn_wave_barrier();

        const int rr = lane_id >> 2;
        const int cc = (lane_id & 3) << 2;
        if (rr < valid_rows) {
            const int out_token = bos + chunk_start + rr;
            const int64_t out_offset =
                (static_cast<int64_t>(out_token) * params.H + h) *
                    params.BT + cc;
            kkt_store_element_v4_direct<ScalarT, SwizzleScratch, 0, 0>(
                A,
                out_offset,
                fla_f32x2{
                    ai00[kkt_scratch_offset<SwizzleScratch>(rr, cc)],
                    ai00[kkt_scratch_offset<SwizzleScratch>(rr, cc + 1)]},
                fla_f32x2{
                    ai00[kkt_scratch_offset<SwizzleScratch>(rr, cc + 2)],
                    ai00[kkt_scratch_offset<SwizzleScratch>(rr, cc + 3)]});
        }
    }

    if (params.K == kKktBK && params.BT == kKktMaxBT) {
        kkt_store_upper_zero_blocks<ScalarT>(
            A, params, tid, valid_rows, bos, chunk_start, h);
    }
}

template <typename ScalarT, bool SwizzleScratch>
__device__ __forceinline__ void kkt_solve_merge_store_mmac_masked(
    float* __restrict__ scratch,
    ScalarT* __restrict__ A,
    const KktSolveParams& params,
    const int tid,
    const int valid_rows,
    const int bos,
    const int chunk_start,
    const int h)
{
    __syncthreads();

    const int id00 = kkt_tri_block_id(0, 0);
    const int id10 = kkt_tri_block_id(1, 0);
    const int id11 = kkt_tri_block_id(1, 1);
    const int id20 = kkt_tri_block_id(2, 0);
    const int id21 = kkt_tri_block_id(2, 1);
    const int id22 = kkt_tri_block_id(2, 2);
    const int id30 = kkt_tri_block_id(3, 0);
    const int id31 = kkt_tri_block_id(3, 1);
    const int id32 = kkt_tri_block_id(3, 2);
    const int id33 = kkt_tri_block_id(3, 3);

    float* ai00 = kkt_scratch_block(scratch, id00);
    float* ai10 = kkt_scratch_block(scratch, id10);
    float* ai11 = kkt_scratch_block(scratch, id11);
    float* ai20 = kkt_scratch_block(scratch, id20);
    float* ai21 = kkt_scratch_block(scratch, id21);
    float* ai22 = kkt_scratch_block(scratch, id22);
    float* ai30 = kkt_scratch_block(scratch, id30);
    float* ai31 = kkt_scratch_block(scratch, id31);
    float* ai32 = kkt_scratch_block(scratch, id32);
    float* ai33 = kkt_scratch_block(scratch, id33);
    float* tmp0 = kkt_scratch_block(scratch, kKktTemp0Block);
    float* tmp1 = kkt_scratch_block(scratch, kKktTemp1Block);
    float* tmp2 = kkt_scratch_block(scratch, kKktTemp2Block);

    kkt_solve_diag16_parallel<true, SwizzleScratch>(scratch, kKktMaxBT);
    kkt_store_upper_zero_blocks<ScalarT>(
        A, params, tid, valid_rows, bos, chunk_start, h);

    kkt_neg_mmac16_left_product_element<0, SwizzleScratch>(
        ai11, ai10, ai00, ai10, tid);
    __builtin_amdgcn_wave_barrier();

    kkt_mmac16_sum2_element<0, SwizzleScratch>(
        ai20, ai00, ai21, ai10, tmp0, tid);
    kkt_mmac16_element<1, SwizzleScratch>(ai22, ai21, tmp1, tid);
    __builtin_amdgcn_wave_barrier();
    kkt_neg_mmac16_element<0, SwizzleScratch>(ai22, tmp0, ai20, tid);
    kkt_neg_mmac16_element<1, SwizzleScratch>(tmp1, ai11, ai21, tid);
    __builtin_amdgcn_wave_barrier();

    kkt_mmac16_sum3_element<0, SwizzleScratch>(
        ai30, ai00, ai31, ai10, ai32, ai20, tmp0, tid);
    kkt_mmac16_sum2_element<1, SwizzleScratch>(
        ai31, ai11, ai32, ai21, tmp1, tid);
    kkt_mmac16_element<2, SwizzleScratch>(ai33, ai32, tmp2, tid);
    __builtin_amdgcn_wave_barrier();
    kkt_neg_mmac16_element<0, SwizzleScratch>(ai33, tmp0, ai30, tid);
    kkt_neg_mmac16_element<1, SwizzleScratch>(ai33, tmp1, ai31, tid);
    kkt_neg_mmac16_element<2, SwizzleScratch>(tmp2, ai22, ai32, tid);
    __syncthreads();

    const float* inv_blocks[kKktNumTriBlocks] = {
        ai00, ai10, ai11, ai20, ai21, ai22, ai30, ai31, ai32, ai33};

    for (int rb = 0; rb < 4; ++rb) {
        const int row_block_start = rb * kKktBC;
        if (row_block_start >= valid_rows) {
            continue;
        }
        for (int cb = 0; cb <= rb; ++cb) {
            const int col_block_start = cb * kKktBC;
            const float* block = inv_blocks[kkt_tri_block_id(rb, cb)];
            for (int element = tid; element < kKktBC * kKktBC; element += blockDim.x) {
                const int rr = element / kKktBC;
                const int cc = element - rr * kKktBC;
                const int row_in_chunk = row_block_start + rr;
                if (row_in_chunk >= valid_rows) {
                    continue;
                }
                const int out_token = bos + chunk_start + row_in_chunk;
                const int64_t out_base =
                    (static_cast<int64_t>(out_token) * params.H + h) * params.BT;
                A[out_base + col_block_start + cc] =
                    ck_tile::type_convert<ScalarT>(
                        block[kkt_scratch_linear_offset<SwizzleScratch>(element)]);
            }
        }
    }
}

template <typename ScalarT, bool UseG, bool SwizzleScratch>
__device__ __forceinline__ void kkt_group_fill_solve_store_fullrows(
    const fla_f32x4 (&dot)[4],
    float* __restrict__ scratch,
    ScalarT* __restrict__ A,
    const KktSolveParams& params,
    const int tid,
    const int bos,
    const int chunk_start,
    const int h_begin,
    const int heads_per_k)
{
    float* beta_lds = scratch + kKktScaleOffset;
    float* g_lds = beta_lds + kKktMaxBT * kKktScaleHeadCap;
#pragma unroll
    for (int head_slot = 0; head_slot < kKktScaleHeadCap; ++head_slot) {
        if (head_slot >= heads_per_k) {
            continue;
        }
        const int h = h_begin + head_slot;
        kkt_store_dot_lower_to_scratch_fullrows<UseG, SwizzleScratch>(
            dot,
            scratch,
            beta_lds + head_slot * kKktMaxBT,
            UseG ? g_lds + head_slot * kKktMaxBT : nullptr);
        kkt_solve_merge_store<ScalarT, true, SwizzleScratch>(
            scratch, A, params, tid, kKktMaxBT, bos, chunk_start, h);
        if (head_slot + 1 < heads_per_k) {
            __syncthreads();
        }
    }
}

template <typename ScalarT, typename BetaT, typename CuIndexT, typename ChunkIndexT,
          bool UseG, bool GroupHeads, bool FullRows, bool TailMmac,
          bool SwizzleScratch>
__global__ __launch_bounds__(256) void
chunk_gated_delta_rule_fwd_kkt_solve_kernel(KktSolveParams params)
{
    using MmaElement = ScalarT;

    extern __shared__ uint8_t smem_base[];
    auto* __restrict__ rhs_lds_tile = reinterpret_cast<MmaElement*>(smem_base);
    auto* __restrict__ scratch = reinterpret_cast<float*>(smem_base);

    const auto* __restrict__ k = static_cast<const ScalarT*>(params.k_ptr);
    const auto* __restrict__ g = static_cast<const float*>(params.g_ptr);
    const auto* __restrict__ beta = static_cast<const BetaT*>(params.beta_ptr);
    auto* __restrict__ A = static_cast<ScalarT*>(params.A_ptr);
    const auto* __restrict__ cu_seqlens = static_cast<const CuIndexT*>(params.cu_seqlens);
    const auto* __restrict__ chunk_indices =
        static_cast<const ChunkIndexT*>(params.chunk_indices);

    const int chunk_pid = static_cast<int>(blockIdx.x);
    const int bh = static_cast<int>(blockIdx.y);
    const int heads_per_k = params.H / params.Hg;
    const int launch_heads = GroupHeads ? params.Hg : params.H;
    const int b = bh / launch_heads;
    const int launched_head = bh - b * launch_heads;
    const int h_begin = GroupHeads ? launched_head * heads_per_k : launched_head;
    const int h_end = GroupHeads ? h_begin + heads_per_k : h_begin + 1;
    const int kg_head = GroupHeads ? launched_head : launched_head / heads_per_k;

    int bos = b * params.T;
    int seq_len = params.T;
    int local_chunk = chunk_pid;
    if (params.is_varlen) {
        const int seq = static_cast<int>(chunk_indices[chunk_pid * 2]);
        local_chunk = static_cast<int>(chunk_indices[chunk_pid * 2 + 1]);
        bos = static_cast<int>(cu_seqlens[seq]);
        if constexpr (!FullRows) {
            const int eos = static_cast<int>(cu_seqlens[seq + 1]);
            seq_len = eos - bos;
        }
    }

    const int chunk_start = local_chunk * params.BT;
    int valid_rows = kKktMaxBT;
    if constexpr (!FullRows) {
        const int remaining = seq_len - chunk_start;
        valid_rows = remaining <= 0 ? 0 : (remaining < params.BT ? remaining : params.BT);
        if (valid_rows <= 0) {
            return;
        }
    }
    if (params.BT > kKktMaxBT) {
        return;
    }

    const int tid = static_cast<int>(threadIdx.x);

    if constexpr (!FullRows) {
        if (params.K != kKktBK || params.BT != kKktMaxBT) {
            for (int h = h_begin; h < h_end; ++h) {
                const int per_h_kg_head = h / heads_per_k;
                kkt_fill_scratch_scalar<ScalarT, BetaT, UseG, SwizzleScratch>(
                    scratch, k, g, beta, params, tid, valid_rows, bos,
                    chunk_start, h, per_h_kg_head);
                kkt_solve_merge_store<ScalarT, false, SwizzleScratch>(
                    scratch, A, params, tid, valid_rows, bos, chunk_start, h);
                if constexpr (GroupHeads) {
                    if (h + 1 < h_end) {
                        __syncthreads();
                    }
                }
            }
            return;
        }
    }

    const int k_t_stride = params.Hg * params.K;

    const int64_t k_tile_base =
        (static_cast<int64_t>(bos + chunk_start) * params.Hg + kg_head) *
        params.K;
    const auto* __restrict__ k_tile =
        reinterpret_cast<const MmaElement*>(k + k_tile_base);

    fla_f32x4 dot[4] = {
        {0.0f, 0.0f, 0.0f, 0.0f},
        {0.0f, 0.0f, 0.0f, 0.0f},
        {0.0f, 0.0f, 0.0f, 0.0f},
        {0.0f, 0.0f, 0.0f, 0.0f}};

    if constexpr (!FullRows) {
        if (valid_rows == kKktMaxBT) {
            kkt_compute_dot_mmac<MmaElement, true>(
                k_tile, k_t_stride, rhs_lds_tile, kKktMaxBT, dot);
            for (int h = h_begin; h < h_end; ++h) {
                kkt_fill_scratch_from_mfma_dot<BetaT, UseG, true, SwizzleScratch>(
                    dot, scratch, g, beta, params, tid, kKktMaxBT, bos,
                    chunk_start, h);
                kkt_solve_merge_store<ScalarT, true, SwizzleScratch>(
                    scratch, A, params, tid, kKktMaxBT, bos, chunk_start, h);
                if constexpr (GroupHeads) {
                    if (h + 1 < h_end) {
                        __syncthreads();
                    }
                }
            }
            return;
        }
    }

    kkt_compute_dot_mmac<MmaElement, FullRows>(
        k_tile, k_t_stride, rhs_lds_tile, valid_rows, dot);
    if constexpr (FullRows) {
        if constexpr (GroupHeads) {
            const int64_t grouped_ctas =
                static_cast<int64_t>(params.B) * params.NT * params.Hg;
            if (heads_per_k <= kKktScaleHeadCap && grouped_ctas >= 512) {
                kkt_preload_group_scales_fullrows<BetaT, UseG>(
                    scratch, g, beta, params, tid, bos, chunk_start,
                    h_begin, heads_per_k);
                kkt_group_fill_solve_store_fullrows<ScalarT, UseG, SwizzleScratch>(
                    dot, scratch, A, params, tid, bos, chunk_start,
                    h_begin, heads_per_k);
                return;
            }
        }
    }
    for (int h = h_begin; h < h_end; ++h) {
        if constexpr (FullRows) {
            kkt_fill_scratch_from_mfma_dot_fullrows_fast<
                BetaT, UseG, SwizzleScratch>(
                dot, scratch, g, beta, params, tid, bos, chunk_start, h);
        } else {
            if (valid_rows <= kKktBC) {
                kkt_fill_scratch_single_block_from_mfma_dot<
                    BetaT, UseG, SwizzleScratch>(
                    dot, scratch, g, beta, params, tid, valid_rows, bos,
                    chunk_start, h);
                kkt_solve_store_single_block<ScalarT, SwizzleScratch>(
                    scratch, A, params, tid, valid_rows, bos, chunk_start, h);
                if constexpr (GroupHeads) {
                    if (h + 1 < h_end) {
                        __syncthreads();
                    }
                }
                continue;
            }
            kkt_fill_scratch_from_mfma_dot<
                BetaT, UseG, FullRows, SwizzleScratch>(
                dot, scratch, g, beta, params, tid, valid_rows, bos,
                chunk_start, h);
        }
        if constexpr (!FullRows && TailMmac) {
            if (valid_rows > 32) {
                kkt_solve_merge_store_mmac_masked<ScalarT, SwizzleScratch>(
                    scratch, A, params, tid, valid_rows, bos, chunk_start, h);
            } else {
                kkt_solve_merge_store<ScalarT, false, SwizzleScratch>(
                    scratch, A, params, tid, valid_rows, bos, chunk_start, h);
            }
        } else {
            kkt_solve_merge_store<ScalarT, FullRows, SwizzleScratch>(
                scratch, A, params, tid, valid_rows, bos, chunk_start, h);
        }
        if constexpr (GroupHeads) {
            if (h + 1 < h_end) {
                __syncthreads();
            }
        }
    }
    return;
}

}  // namespace FLA_NAMESPACE
