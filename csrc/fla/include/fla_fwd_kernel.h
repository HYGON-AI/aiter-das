// SPDX-License-Identifier: MIT
#pragma once

#include "kernel_traits.h"
#include "block_info.h"
#include "utils.h"

namespace FLA_NAMESPACE {

#ifndef FLA_BV32_GEMM0_H_READAHEAD
#define FLA_BV32_GEMM0_H_READAHEAD 1
#endif

template <typename Kernel_traits, typename Params, bool FullChunk,
          bool WAlreadyPrefetched = false, bool PrefetchNextW = false,
          bool PrefetchNextWCheckBounds = false,
          int WPrefetchYoungerVmem = 0, bool EndBarrier = true>
__device__ __forceinline__ void
run_chunk_gated_delta_rule_fwd_chunk_bv16(
    const Params &params,
    const int chunk,
    const int t_begin,
    const int valid_t,
    const int last_idx,
    const int v_begin,
    const typename Kernel_traits::Element *__restrict__ k_ptr,
    const typename Kernel_traits::Element *__restrict__ w_ptr,
    const typename Kernel_traits::Element *__restrict__ u_ptr,
    typename Kernel_traits::Element *__restrict__ h_ptr,
    typename Kernel_traits::Element *__restrict__ v_new_ptr,
    const float *__restrict__ g_ptr,
    const float *__restrict__ gk_ptr,
    fla_f32x2 (&state_reg)[4],
    typename Kernel_traits::Element *__restrict__ v_tile,
    typename Kernel_traits::Element *__restrict__ h_low_tile,
    typename Kernel_traits::Element *__restrict__ w_lds_tile,
    typename Kernel_traits::Element *__restrict__ k_lds_tile,
    const int next_valid_t = Kernel_traits::kBlockT)
{
    static_assert(Kernel_traits::kBlockV == 16,
                  "chunk_gated_delta_rule_fwd currently supports BV16 only");

    using Element = typename Kernel_traits::Element;
    using index_t = typename Kernel_traits::index_t;
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;

    if constexpr (!FullChunk) {
        if (valid_t <= 0 || last_idx < 0) {
            return;
        }
    }

    constexpr int BK = Kernel_traits::kBlockK;
    constexpr int BV = Kernel_traits::kBlockV;
    constexpr int BT = Kernel_traits::kBlockT;
    constexpr int V_TILE_STRIDE = Kernel_traits::kVTileStride;
    constexpr int H_LOW_STRIDE = Kernel_traits::kHLowStride;
    constexpr int kResidualVec = 4;

    constexpr bool Use_G          = Kernel_traits::Use_G;
    constexpr bool Use_GK         = Kernel_traits::Use_GK;
    constexpr bool Save_new_value = Kernel_traits::Save_new_value;
    constexpr bool Use_exp2       = Kernel_traits::Use_exp2;
    constexpr bool Use_safe_exp   = Kernel_traits::Use_safe_exp;
    // BV16 stages W/K via direct-to-LDS.  GK uses the late-K schedule so the
    // GEMM0 publication wait only has to prove the carried W tile is resident
    // in LDS before GEMM0 reads it.
    constexpr bool kDelayKPrefetchUntilAfterGemm0 =
        Use_GK && FullChunk && WAlreadyPrefetched;
    constexpr int kWCnt = 4;
    constexpr int kKCnt = 4;
    constexpr int kKBeforeGemm0Cnt = kDelayKPrefetchUntilAfterGemm0 ? 0 : kKCnt;
    constexpr int kHSnapshotCnt = 1;
    constexpr int kWNextCnt = PrefetchNextW ? kWCnt : 0;
    constexpr int kGCnt = Use_G ? 2 : 0;
    constexpr int kUCnt = 1;
    constexpr int kGKCnt = Use_GK ? 2 : 0;
    constexpr int kVNewStoreCnt = Save_new_value ? 1 : 0;
    constexpr int kYoungerThanCarriedWAtGemm0 =
        WPrefetchYoungerVmem + kGCnt + kUCnt + kKBeforeGemm0Cnt;
    constexpr int kYoungerThanRowGAfterGemm0Vmem =
        kUCnt + kKCnt;
    constexpr int kYoungerThanUAtResidualVmem =
        kKCnt + kHSnapshotCnt + kWNextCnt + kGKCnt;
    constexpr int kYoungerThanKAtGemm1Vmem =
        kHSnapshotCnt + kWNextCnt + kGKCnt + kVNewStoreCnt;
    static_assert(!PrefetchNextW || (FullChunk && WAlreadyPrefetched),
                  "W_next prefetch is only valid for full steady chunks");
    static_assert(!PrefetchNextWCheckBounds || PrefetchNextW,
                  "checked W_next prefetch requires PrefetchNextW");
    static_assert(WAlreadyPrefetched,
                  "BV16 outer loop must carry W into every chunk");

    const int tid = threadIdx.x;
    const int warp_id = tid / 64;
    const int lane_id = tid & 63;
    const int lane_m = lane_id & 15;
    const int lane_k_group = lane_id >> 4;
    const int t_local = warp_id * 16 + lane_m;
    const int k0 = warp_id * 32 + lane_m * 2;
    const int k1 = k0 + 1;
    const bool valid_row = FullChunk || (t_local < valid_t);

    // 1. Stage or consume W.  Steady full chunks consume a W tile that was
    // issued by the prologue or previous chunk epilogue.  For carried W, delay
    // the wait until just before GEMM0 so current G loads and K prefetch can be
    // issued while the W direct-to-LDS writes finish.  Non-carried W still uses
    // the conservative publication point immediately after staging.
    // if constexpr (!WAlreadyPrefetched) {
    //     if constexpr (FullChunk) {
    //         fla_prefetch_w_to_lds<Element, BT, BK, Kernel_traits::kNWarps>(
    //             w_lds_tile,
    //             w_ptr + index_t(t_begin) * params.w_row_stride,
    //             params.w_row_stride);
    //     } else {
    //         fla_prefetch_w_to_lds<Element, BT, BK, Kernel_traits::kNWarps, true>(
    //             w_lds_tile,
    //             w_ptr + index_t(t_begin) * params.w_row_stride,
    //             params.w_row_stride,
    //             valid_t);
    //     }
    //     wait_all_and_barrier();
    // }
    // 2. Issue row-G inputs before K.  U stays close to residual consumption:
    // moving the CK Tile U builtin across GEMM0 was tested and produced
    // repeat-to-repeat v_new drift even with vmcnt(0).
    uint32_t state_g_bits = 0;
    uint32_t row_g_last_bits = 0;
    uint32_t row_g_cur_bits = 0;
    uint32_t state_gk0_bits = 0;
    uint32_t state_gk1_bits = 0;
    if constexpr (Use_G) {
        const int32_t row_g_last_offset_bytes =
            static_cast<int32_t>(
                index_t(last_idx) * params.g_row_stride * sizeof(float));
        const int32_t row_g_cur_offset_bytes =
            static_cast<int32_t>(
                index_t(t_begin + t_local) * params.g_row_stride *
                sizeof(float));
        // OOB (invalid tail rows) is handled by the hardware buffer
        // descriptor via voffset=-1, so full and tail chunks share the same
        // load; only the row-G-cur offset differs by valid_row.
        row_g_last_bits =
            fla_buffer_load_vgpr<1>(g_ptr, row_g_last_offset_bytes);
        row_g_cur_bits = fla_buffer_load_vgpr<1>(
            g_ptr, valid_row ? row_g_cur_offset_bytes : -1);
        state_g_bits = row_g_last_bits;
    }

    const index_t u_element_offset =
        index_t(t_begin + t_local) * params.u_row_stride +
        v_begin + lane_k_group * kResidualVec;
    ElementVec4 u_buf = {};
    const int32_t u_voffset =
        valid_row ? static_cast<int32_t>(u_element_offset * sizeof(Element))
                  : -1;
    u_buf = fla_buffer_load_element_v4_vgpr<Element>(u_ptr, u_voffset);

    // 3. Stage K into its independent LDS tile.  The steady carried-W GK path
    // delays K until after GEMM0 so the GEMM0 publication wait proves only W
    // D2L completion before W/H LDS reads.  Tail and diagnostic paths keep the
    // original conservative issue point.
    if constexpr (FullChunk && !kDelayKPrefetchUntilAfterGemm0) {
        fla_prefetch_k_to_lds<Element, BT, BK, Kernel_traits::kNWarps>(
            k_lds_tile,
            k_ptr + index_t(t_begin) * params.k_row_stride,
            params.k_row_stride);
    } else if constexpr (!FullChunk) {
        fla_prefetch_k_to_lds<Element, BT, BK, Kernel_traits::kNWarps, true>(
            k_lds_tile,
            k_ptr + index_t(t_begin) * params.k_row_stride,
            params.k_row_stride,
            valid_t);
    }

    // GEMM0 is the first consumer of the carried W tile and of h_low from
    // the previous state update.  Wait only far enough to publish those LDS
    // values: keep the previous chunk's younger VMEM and current row-G/U
    // loads outstanding.  For GK or explicit late-K, K is issued after
    // GEMM0 so W/H LDS reads do not overlap K D2L.
    wait_vmcnt_lgkmcnt0_barrier<kYoungerThanCarriedWAtGemm0>();

    // 4. GEMM0: projection = W @ H.  The wait above publishes W/H LDS and
    // closes their cross-wave lifetime before any later direct-to-LDS reuse.
    fla_f32x4 c0 = {0.0f, 0.0f, 0.0f, 0.0f};
#pragma unroll
    for (int k_stage = 0; k_stage < 4; ++k_stage) {
        const fla_u32x4 w_pack =
            fla_read_w_stage<Element, BT, BK, Kernel_traits::kNWarps>(
                w_lds_tile, k_stage);
        const fla_u32x4 h_pack =
            fla_read_h_stage_b128_kmajor_bv16<Element, H_LOW_STRIDE>(
                h_low_tile, k_stage);

        ElementVec4 a = fla_vec4_from_pack<Element>(w_pack, 0);
        ElementVec4 b = fla_vec4_from_pack<Element>(h_pack, 0);
        c0 = fla_mmac_f32_16x16x16<Element>(a, b, c0);

        a = fla_vec4_from_pack<Element>(w_pack, 4);
        b = fla_vec4_from_pack<Element>(h_pack, 4);
        c0 = fla_mmac_f32_16x16x16<Element>(a, b, c0);
    }
    fla_f32x4 proj_v4 = fla_make_gemm0_projection_v4(c0, lane_k_group);

    // Keep row-G math below GEMM0 in the backend schedule.  This is a compiler
    // scheduling fence only; VMEM/LDS completion is still controlled by the
    // explicit waitcnt/barrier sites.
    compiler_sched_barrier();

    if constexpr (kDelayKPrefetchUntilAfterGemm0) {
        // K is first consumed by GEMM1.  Issue it after GEMM0 to avoid sharing
        // the GEMM0 W/H LDS read window with outstanding K direct-to-LDS writes;
        // the GEMM1 publication point below waits for these four VMEM ops.
        fla_prefetch_k_to_lds<Element, BT, BK, Kernel_traits::kNWarps>(
            k_lds_tile,
            k_ptr + index_t(t_begin) * params.k_row_stride,
            params.k_row_stride);
    }

    // Row-G is consumed only by the residual scale.  Wait for the two G loads
    // after GEMM0, leaving the early U load and K direct-to-LDS prefetch
    // outstanding.  If a previous chunk's v_new store is still older than G,
    // vmcnt will naturally drain it as well; that is conservative but keeps
    // the dependency proof simple while validating this schedule.
    if constexpr (Use_G) {
        wait_vmcnt<kYoungerThanRowGAfterGemm0Vmem>();
    }

    float row_scale = 1.0f;
    if constexpr (Use_G) {
        const float g_last = ck_tile::bit_cast<float>(row_g_last_bits);
        const float g_cur = ck_tile::bit_cast<float>(row_g_cur_bits);
        const float diff = g_last - g_cur;
        row_scale = fla_exp<Use_safe_exp, Use_exp2>(diff);
    }

    // 5. Snapshot chunk-start state after GEMM0 has consumed h_low but before
    // any state update.
    fla_store_h_snapshot_v8_from_h_low_kmajor_bv16<
        Element, Params, index_t, BK, H_LOW_STRIDE,
        Kernel_traits::kThreads,
        FullChunk>(
        params, chunk, v_begin, h_low_tile, h_ptr, tid);
    wait_lgkmcnt0_barrier();

    if constexpr (PrefetchNextW) {
        if constexpr (PrefetchNextWCheckBounds) {
            fla_prefetch_w_to_lds<Element, BT, BK, Kernel_traits::kNWarps, true>(
                w_lds_tile,
                w_ptr + index_t(t_begin + BT) * params.w_row_stride,
                params.w_row_stride,
                next_valid_t);
        } else {
            fla_prefetch_w_to_lds<Element, BT, BK, Kernel_traits::kNWarps>(
                w_lds_tile,
                w_ptr + index_t(t_begin + BT) * params.w_row_stride,
                params.w_row_stride);
        }
    }

    // 6. Optional GK is issued after W_next.  Therefore W_next is older than GK
    // and cannot be counted as a younger VMEM op when waiting for GK later.
    if constexpr (Use_GK) {
        const int32_t state_gk0_offset_bytes =
            static_cast<int32_t>(
                (index_t(last_idx) * params.gk_row_stride + k0) *
                sizeof(float));
        const int32_t state_gk1_offset_bytes =
            static_cast<int32_t>(
                (index_t(last_idx) * params.gk_row_stride + k1) *
                sizeof(float));
        state_gk0_bits =
            fla_buffer_load_vgpr<1>(gk_ptr, state_gk0_offset_bytes);
        state_gk1_bits =
            fla_buffer_load_vgpr<1>(gk_ptr, state_gk1_offset_bytes);
    }
    // Wait for U while keeping younger K direct-to-LDS, h snapshot, W_next,
    // and optional GK loads in flight.
    wait_vmcnt<kYoungerThanUAtResidualVmem>();

    ElementVec4 u_v4 = {};
#pragma unroll
    for (int s = 0; s < kResidualVec; ++s) {
        u_v4[s] = u_buf[s];
    }
    fla_f32x4 raw_v4 = {
        ck_tile::type_convert<float>(u_v4[0]) - proj_v4[0],
        ck_tile::type_convert<float>(u_v4[1]) - proj_v4[1],
        ck_tile::type_convert<float>(u_v4[2]) - proj_v4[2],
        ck_tile::type_convert<float>(u_v4[3]) - proj_v4[3]};
    if constexpr (!FullChunk) {
        if (!valid_row) {
            raw_v4 = fla_f32x4{0.0f, 0.0f, 0.0f, 0.0f};
        }
    }

    fla_f32x4 saved_v_new_v4;
    if constexpr (Save_new_value && Use_G) {
        saved_v_new_v4 = raw_v4;
    }

    if constexpr (Use_G) {
        if constexpr (FullChunk) {
            fla_scale_v4_pairs(raw_v4, row_scale);
        } else {
            if (valid_row) {
                fla_scale_v4_pairs(raw_v4, row_scale);
            } else {
                raw_v4 = fla_f32x4{0.0f, 0.0f, 0.0f, 0.0f};
            }
        }
    }
    compiler_sched_barrier();
    fla_store_v_tile_m32x16_bv16_swizzled<Element>(
        v_tile, t_local, raw_v4, lane_k_group);

    if constexpr (Save_new_value) {
        fla_f32x4 store_v4 = raw_v4;
        if constexpr (Use_G) {
            store_v4 = saved_v_new_v4;
        }
        const int32_t v_new_offset_bytes =
            valid_row
                ? static_cast<int32_t>((index_t(t_begin + t_local) *
                                            params.v_new_row_stride +
                                        v_begin + lane_k_group * kResidualVec) *
                                       sizeof(Element))
                : -1;
        compiler_sched_barrier();
        fla_buffer_store_element_v4_vgpr<Element>(
            v_new_ptr,
            v_new_offset_bytes,
            fla_f32x2{store_v4[0], store_v4[1]},
            fla_f32x2{store_v4[2], store_v4[3]});
    }

    // 6. This is the chunk-internal LDS publication point before GEMM1:
    //   * drains K direct-to-LDS VMEM before reading k_lds_tile,
    //   * waits/publishes v_tile LDS writes from all waves,
    //   * leaves younger h/W_next/GK/v_new VMEM outstanding in the common full
    //     chunk path.  GK is waited only before the state update; W_next remains
    //     carried to the following chunk.
    // Keeping this wait here, instead of at U consumption, restores overlap
    // between K prefetch and residual/v_tile/v_new while preserving LDS
    // lifetime correctness.
    wait_vmcnt_lgkmcnt0_barrier<kYoungerThanKAtGemm1Vmem>();
    // 7. GEMM1: state delta = K^T @ V.
    fla_f32x4 c00 = {0.0f, 0.0f, 0.0f, 0.0f};
    fla_f32x4 c01 = {0.0f, 0.0f, 0.0f, 0.0f};
    // Hand-scheduled GEMM1 LDS pipeline.  The entrance barrier above has
    // published K D2L and v_tile stores for all waves.  The waitcnt helpers
    // below carry +v dependencies on the packs consumed by the next MMAC; a
    // plain memory-clobber wait is not enough, because the compiler may move
    // register-only MMACs before a standalone s_waitcnt.  Keep one future K
    // read outstanding with lgkmcnt(1):
    //   K0, V0, K1 -> wait_dep(1) -> stage0 -> V1, K2 -> wait_dep(1) ...
    // The final stage has no future K, so stage2 publishes V3 with wait_dep(0)
    // before stage3 consumes K3/V3.
    fla_u32x4 k_pack =
        fla_read_k_stage_alt_asm<Element, BT, BK, Kernel_traits::kNWarps>(
            k_lds_tile, 0);
    fla_u32x4 v_pack =
        fla_read_v_stage_m32x16_asm<Element, BT, V_TILE_STRIDE>(
            v_tile, 0);
    fla_u32x4 k_next =
        fla_read_k_stage_alt_asm<Element, BT, BK, Kernel_traits::kNWarps>(
            k_lds_tile, 1);
    wait_lgkmcnt_dep<1>(k_pack, v_pack, k_next);

#pragma unroll
    for (int k_stage = 0; k_stage < 3; ++k_stage) {
        const ElementVec4 a0 = fla_vec4_from_pack<Element>(v_pack, 0);
        const ElementVec4 b0 = fla_vec4_from_pack<Element>(k_pack, 0);
        const ElementVec4 b1 = fla_vec4_from_pack<Element>(k_pack, 4);
        c00 = fla_mmac_f32_16x16x16_trans_c<Element>(a0, b0, c00);
        c01 = fla_mmac_f32_16x16x16_trans_c<Element>(a0, b1, c01);

        fla_u32x4 v_next =
            fla_read_v_stage_m32x16_asm<Element, BT, V_TILE_STRIDE>(
                v_tile, k_stage + 1);
        fla_u32x4 k_next2 = {0, 0, 0, 0};
        if (k_stage != 2) {
            k_next2 =
                fla_read_k_stage_alt_asm<Element, BT, BK,
                                         Kernel_traits::kNWarps>(
                    k_lds_tile, k_stage + 2);
            wait_lgkmcnt_dep<1>(k_next, v_next, k_next2);
        } else {
            wait_lgkmcnt_dep<0>(k_next, v_next);
        }
        k_pack = k_next;
        v_pack = v_next;
        k_next = k_next2;
    }

    {
        const ElementVec4 a0 = fla_vec4_from_pack<Element>(v_pack, 0);
        const ElementVec4 b0 = fla_vec4_from_pack<Element>(k_pack, 0);
        const ElementVec4 b1 = fla_vec4_from_pack<Element>(k_pack, 4);
        c00 = fla_mmac_f32_16x16x16_trans_c<Element>(a0, b0, c00);
        c01 = fla_mmac_f32_16x16x16_trans_c<Element>(a0, b1, c01);
    }
    // GEMM1 has finished consuming K/v LDS when every wave reaches this point.
    // With GK, W_next was issued before GK, so it must be drained together with
    // GK before consuming the GK payload.  Only the optional v_new store is
    // truly younger than GK and may remain outstanding.
    if constexpr (Use_GK) {
        wait_vmcnt<kVNewStoreCnt>();
    } else {
        wait_lgkmcnt0_barrier();
    }

    float state_scale_common = 1.0f;
    if constexpr (Use_G) {
        const float g_last = ck_tile::bit_cast<float>(state_g_bits);
        state_scale_common = fla_exp<false, Use_exp2>(g_last);
    }
    float state_scale_k0 = state_scale_common;
    float state_scale_k1 = state_scale_common;
    if constexpr (Use_GK) {
        const float gk_last0 = ck_tile::bit_cast<float>(state_gk0_bits);
        const float gk_last1 = ck_tile::bit_cast<float>(state_gk1_bits);
        state_scale_k0 *= fla_exp<false, Use_exp2>(gk_last0);
        state_scale_k1 *= fla_exp<false, Use_exp2>(gk_last1);
    }
    const fla_f32x2 state_scale_pair = {state_scale_k0, state_scale_k1};

#pragma unroll
    for (int s = 0; s < 4; ++s) {
        const int v_local = lane_k_group + s * 4;
        const fla_f32x2 delta = {c00[s], c01[s]};
        const fla_f32x2 next = {
            state_reg[s][0] * state_scale_pair[0] + delta[0],
            state_reg[s][1] * state_scale_pair[1] + delta[1]};
        state_reg[s] = next;
        fla_store_h_low_pair_kmajor<Element, H_LOW_STRIDE>(
            h_low_tile, v_local, k0, next);
    }
    if constexpr (EndBarrier) {
        wait_all_and_barrier();
    }
}

template <typename Element, int STRIDE>
__device__ __forceinline__ void
fla_store_h_low_pair_linear(Element *h_low_base, const int v_local,
                            const int k_col_even, const fla_f32x2 h_pair)
{
    h_low_base[v_local * STRIDE + k_col_even] =
        ck_tile::type_convert<Element>(h_pair[0]);
    h_low_base[v_local * STRIDE + k_col_even + 1] =
        ck_tile::type_convert<Element>(h_pair[1]);
}

template <typename Element, typename Params, typename Index, int BV, int BK,
          int STRIDE, int kThreads>
__device__ __forceinline__ void
fla_store_h_snapshot_linear_bv32(
    const Params &params, const int chunk, const int v_begin,
    const Element *__restrict__ h_low_base, Element *__restrict__ h_ptr,
    const int tid)
{
#pragma unroll
    for (int vec_idx = tid; vec_idx < (BV * BK) / 8; vec_idx += kThreads) {
        const int v_local = vec_idx / (BK / 8);
        const int k_vec = (vec_idx - v_local * (BK / 8)) * 8;
        const int v_col = v_begin + v_local;
        const fla_u32x4 h_pack =
            *reinterpret_cast<const fla_u32x4 *>(
                h_low_base + v_local * STRIDE + k_vec);
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

// Accumulate one W stage against two already-resident H packs (v_n=0/1).
template <typename Element>
__device__ __forceinline__ void
fla_gemm0_mmac_w_h_bv32(const fla_u32x4 &w_pack, const fla_u32x4 h_pack[2],
                        fla_f32x4 (&c_proj)[2])
{
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;
#pragma unroll
    for (int v_n = 0; v_n < 2; ++v_n) {
        const ElementVec4 a0 = fla_vec4_from_pack<Element>(w_pack, 0);
        const ElementVec4 b0 = fla_vec4_from_pack<Element>(h_pack[v_n], 0);
        c_proj[v_n] = fla_mmac_f32_16x16x16<Element>(a0, b0, c_proj[v_n]);
        const ElementVec4 a1 = fla_vec4_from_pack<Element>(w_pack, 4);
        const ElementVec4 b1 = fla_vec4_from_pack<Element>(h_pack[v_n], 4);
        c_proj[v_n] = fla_mmac_f32_16x16x16<Element>(a1, b1, c_proj[v_n]);
    }
}

// Consumes one already-issued W stage (private VGPR, no cross-wave
// dependency) against H read live from LDS, accumulating into c_proj.
// YoungerVmem is the number of vector-memory ops still outstanding that are
// younger than this W stage in the age model built by the pipelined issue
// order in run_chunk_gated_delta_rule_fwd_chunk_bv32_mmac (W -> G ->
// U -> K-prefetch); wait_vmcnt<YoungerVmem>() proves this specific W stage
// is ready without draining anything younger.
template <typename Element, int K_STAGE, int YoungerVmem, bool WAlreadyInVgpr = false>
__device__ __forceinline__ void
fla_gemm0_consume_w_stage_bv32(const fla_u32x4 &w_pack, Element *h_low_tile,
                               fla_f32x4 (&c_proj)[2])
{
    fla_u32x4 h_pack[2];
#pragma unroll
    for (int v_n = 0; v_n < 2; ++v_n) {
        h_pack[v_n] = fla_read_h_stage_b128_swizzled_bv32<Element>(
            h_low_tile, K_STAGE, v_n);
    }
    if constexpr (!WAlreadyInVgpr) {
        wait_vmcnt<YoungerVmem>();
    }
    fla_gemm0_mmac_w_h_bv32<Element>(w_pack, h_pack, c_proj);
}

// One pipelined GEMM0 k_stage: prefetch next H, wait W, MMAC, rotate H packs.
template <typename Element, int K_STAGE, int kAfterW, bool WAlreadyInVgpr>
__device__ __forceinline__ void
fla_gemm0_run_bv32_one_stage(const fla_u32x4 w_pack[4], fla_u32x4 (&h_pack)[2],
                              Element *h_low_tile, fla_f32x4 (&c_proj)[2])
{
    fla_u32x4 h_next[2] = {};
    if constexpr (K_STAGE != 3) {
        h_next[0] = fla_read_h_stage_b128_swizzled_bv32<Element>(
            h_low_tile, K_STAGE + 1, 0);
        h_next[1] = fla_read_h_stage_b128_swizzled_bv32<Element>(
            h_low_tile, K_STAGE + 1, 1);
    }
    if constexpr (!WAlreadyInVgpr) {
        constexpr int kWCnt = 4;
        wait_vmcnt<kWCnt - 1 - K_STAGE + kAfterW>();
    }
    fla_gemm0_mmac_w_h_bv32<Element>(w_pack[K_STAGE], h_pack, c_proj);
    h_pack[0] = h_next[0];
    h_pack[1] = h_next[1];
}

// Full GEMM0: W[4] x H_low with optional one-stage-ahead H ds_read pipeline.
// Read-ahead issues the next k_stage's two H b128 loads before the current
// stage's W wait + MMACs so the compiler can overlap lgkmcnt with VMEM
// drain and MMAC math.
template <typename Element, int kAfterW, bool WAlreadyInVgpr>
__device__ __forceinline__ void
fla_gemm0_run_bv32(const fla_u32x4 w_pack[4], Element *h_low_tile,
                   fla_f32x4 (&c_proj)[2])
{
#if FLA_BV32_GEMM0_H_READAHEAD
    fla_u32x4 h_pack[2];
    h_pack[0] =
        fla_read_h_stage_b128_swizzled_bv32<Element>(h_low_tile, 0, 0);
    h_pack[1] =
        fla_read_h_stage_b128_swizzled_bv32<Element>(h_low_tile, 0, 1);
    fla_gemm0_run_bv32_one_stage<Element, 0, kAfterW, WAlreadyInVgpr>(
        w_pack, h_pack, h_low_tile, c_proj);
    fla_gemm0_run_bv32_one_stage<Element, 1, kAfterW, WAlreadyInVgpr>(
        w_pack, h_pack, h_low_tile, c_proj);
    fla_gemm0_run_bv32_one_stage<Element, 2, kAfterW, WAlreadyInVgpr>(
        w_pack, h_pack, h_low_tile, c_proj);
    fla_gemm0_run_bv32_one_stage<Element, 3, kAfterW, WAlreadyInVgpr>(
        w_pack, h_pack, h_low_tile, c_proj);
#else
    constexpr int kWCnt = 4;
    fla_gemm0_consume_w_stage_bv32<Element, 0, kWCnt - 1 + kAfterW,
                                    WAlreadyInVgpr>(w_pack[0], h_low_tile,
                                                    c_proj);
    fla_gemm0_consume_w_stage_bv32<Element, 1, kWCnt - 2 + kAfterW,
                                    WAlreadyInVgpr>(w_pack[1], h_low_tile,
                                                    c_proj);
    fla_gemm0_consume_w_stage_bv32<Element, 2, kWCnt - 3 + kAfterW,
                                    WAlreadyInVgpr>(w_pack[2], h_low_tile,
                                                    c_proj);
    fla_gemm0_consume_w_stage_bv32<Element, 3, kWCnt - 4 + kAfterW,
                                    WAlreadyInVgpr>(w_pack[3], h_low_tile,
                                                    c_proj);
#endif
}

template <typename Kernel_traits, typename Params, bool FullChunk,
          bool WAlreadyCarried = false, bool PrefetchNextW = false>
__device__ __forceinline__ void
run_chunk_gated_delta_rule_fwd_chunk_bv32_mmac(
    const Params &params,
    const int chunk,
    const int t_begin,
    const int valid_t,
    const int last_idx,
    const int v_begin,
    const typename Kernel_traits::Element *__restrict__ k_ptr,
    const typename Kernel_traits::Element *__restrict__ w_ptr,
    const typename Kernel_traits::Element *__restrict__ u_ptr,
    typename Kernel_traits::Element *__restrict__ h_ptr,
    typename Kernel_traits::Element *__restrict__ v_new_ptr,
    const float *__restrict__ g_ptr,
    const float *__restrict__ gk_ptr,
    fla_f32x2 (&state_reg)[8],
    fla_u32x4 (&w_carried)[4],
    typename Kernel_traits::Element *__restrict__ v_tile,
    typename Kernel_traits::Element *__restrict__ h_low_tile,
    typename Kernel_traits::Element *__restrict__ w_lds_tile,
    typename Kernel_traits::Element *__restrict__ k_lds_tile,
    const int next_valid_t = Kernel_traits::kBlockT)
{
    static_assert(Kernel_traits::kBlockV == 32,
                  "run_chunk_gated_delta_rule_fwd_chunk_bv32_mmac requires BV32");

    using Element = typename Kernel_traits::Element;
    using index_t = typename Kernel_traits::index_t;
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;

    (void)w_lds_tile;

    const int tid = threadIdx.x;

    if constexpr (!FullChunk) {
        if (valid_t <= 0 || last_idx < 0) {
            return;
        }
    }

    constexpr int BK = Kernel_traits::kBlockK;
    constexpr int BV = Kernel_traits::kBlockV;
    constexpr int BT = Kernel_traits::kBlockT;
    constexpr int V_TILE_STRIDE = Kernel_traits::kVTileStride;
    constexpr int H_LOW_STRIDE = Kernel_traits::kHLowStride;

    constexpr bool Use_G          = Kernel_traits::Use_G;
    constexpr bool Use_GK         = Kernel_traits::Use_GK;
    constexpr bool Save_new_value = Kernel_traits::Save_new_value;
    constexpr bool Use_exp2       = Kernel_traits::Use_exp2;
    constexpr bool Use_safe_exp   = Kernel_traits::Use_safe_exp;

    const int warp_id = tid / 64;
    const int lane_id = tid & 63;
    const int lane_m = lane_id & 15;
    const int lane_g = lane_id >> 4;
    const int t_local = warp_id * 16 + lane_m;
    const int k0 = warp_id * 32 + lane_m * 2;
    const int k1 = k0 + 1;
    const bool valid_row = FullChunk || (t_local < valid_t);

    uint32_t row_g_last_bits = 0;
    uint32_t row_g_cur_bits = 0;
    uint32_t state_gk0_bits = 0;
    uint32_t state_gk1_bits = 0;

    const index_t u_element_offset =
        index_t(t_begin + t_local) * params.u_row_stride +
        v_begin + lane_g * 8;
    const int32_t u_voffset =
        valid_row ? static_cast<int32_t>(u_element_offset * sizeof(Element))
                  : -1;

    // 1. GEMM0: W from GMEM, H from LDS (linear b128), MMAC accumulation.
    const index_t w_tensor_elems =
        index_t(params.T) * params.H * params.K;

    // ------------------------------------------------------------------
    // Pipelined memory issue: fire chunk-local GMEM/D2L in consumption
    // order W -> G -> U -> K so the vmcnt age model matches 先发先用.
    // K direct-to-LDS is the last VMEM consumer (GEMM1); its D2L can overlap
    // GEMM0, row-G scale, h-snapshot, GK, and residual/v_tile while U is
    // drained earlier.  Steady chunks may carry W_next in VGPR across chunks.
    //
    // Every helper always emits a fixed instruction count (OOB via
    // voffset=-1 / CheckBounds).  FullChunk only selects the K-prefetch
    // bounds-check path; issue order and relaxed waitcnt sites are identical.
    // ------------------------------------------------------------------
    constexpr int kWCnt         = 4;
    constexpr int kGCnt         = Use_G ? 2 : 0;
    constexpr int kKPrefetchCnt = 4;
    constexpr int kUCnt         = 1;
    constexpr int kHSnapshotCnt =
        (BV * BK) / 8 / Kernel_traits::kThreads;
    constexpr int kGKCnt        = Use_GK ? 2 : 0;
    constexpr int kVNewStoreCnt = Save_new_value ? 1 : 0;
    constexpr int kWNextCnt     = PrefetchNextW ? kWCnt : 0;
    static_assert(!PrefetchNextW || (FullChunk && WAlreadyCarried),
                  "W_next VGPR carry is only valid for full carried chunks");
    // Steady-chunk VMEM age offsets (W_next VGPR carry on full chunks).
    constexpr int kYoungerThanRowGAfterGemm0Vmem =
        kUCnt + kKPrefetchCnt;
    constexpr int kYoungerThanRawUAtResidualVmem =
        kKPrefetchCnt + kHSnapshotCnt + kGKCnt + kWNextCnt;
    constexpr int kYoungerThanKAtGemm1Vmem =
        kHSnapshotCnt + kGKCnt + kVNewStoreCnt + kWNextCnt;

    fla_u32x4 w_pack[4] = {};
    fla_u32x4 u_pack = {0, 0, 0, 0};

    // (1) W: 4-stage per-thread VGPR loads, or consume carried W_next.
    if constexpr (WAlreadyCarried) {
#pragma unroll
        for (int k_stage = 0; k_stage < 4; ++k_stage) {
            w_pack[k_stage] = w_carried[k_stage];
        }
    } else {
        fla_load_w_tile_bv32_vgpr<Element, index_t, BK>(
            w_ptr, index_t(t_begin), params.w_row_stride, valid_row,
            w_tensor_elems, w_pack);
    }

    if constexpr (Use_G) {
        // (2) G.
        const int32_t row_g_last_offset_bytes =
            static_cast<int32_t>(
                index_t(last_idx) * params.g_row_stride * sizeof(float));
        const int32_t row_g_cur_offset_bytes =
            static_cast<int32_t>(
                index_t(t_begin + t_local) * params.g_row_stride *
                sizeof(float));
        row_g_last_bits =
            fla_buffer_load_vgpr<1>(g_ptr, row_g_last_offset_bytes);
        row_g_cur_bits = fla_buffer_load_vgpr<1>(
            g_ptr, valid_row ? row_g_cur_offset_bytes : -1);
    }

    // (3) U: residual target prefetch (OOB via voffset=-1).  Issued before
    // K so U is older in the VMEM queue and can be drained at residual
    // consumption while K direct-to-LDS stays outstanding.
    u_pack = fla_buffer_load_element_v8_vgpr<Element>(u_ptr, u_voffset);

    // (4) K: direct-to-LDS prefetch for GEMM1.  Steady chunks take the
    // inline-asm D2L path (CheckBounds=false); tail keeps CheckBounds=true.
    // Both emit exactly kKPrefetchCnt VMEM ops.  D2L payload is not visible
    // to ds_read until wait_vmcnt_lgkmcnt0_barrier at the GEMM1 entry.
    if constexpr (FullChunk) {
        fla_prefetch_k_to_lds<Element, BT, BK, Kernel_traits::kNWarps, false>(
            k_lds_tile,
            k_ptr + index_t(t_begin) * params.k_row_stride,
            params.k_row_stride,
            BT);
    } else {
        fla_prefetch_k_to_lds<Element, BT, BK, Kernel_traits::kNWarps, true>(
            k_lds_tile,
            k_ptr + index_t(t_begin) * params.k_row_stride,
            params.k_row_stride,
            valid_t);
    }

    fla_f32x4 c_proj[2] = {{0.0f, 0.0f, 0.0f, 0.0f},
                           {0.0f, 0.0f, 0.0f, 0.0f}};

    // GEMM0 consumes W against h_low read live from LDS.  Carried W_next is
    // already resident in VGPR after the previous chunk-exit wait.  That wait
    // may leave the previous chunk's v_new store outstanding; it is older than
    // this chunk's G/U/K VMEM and must not be counted as "younger" in the
    // waitcnt constants below.  The first current-tensor wait will drain it
    // conservatively while still allowing overlap with GEMM0.
    constexpr int kAfterW = kGCnt + kKPrefetchCnt + kUCnt;
    constexpr bool kWAlreadyInVgpr = WAlreadyCarried;
    fla_gemm0_run_bv32<Element, kAfterW, kWAlreadyInVgpr>(
        w_pack, h_low_tile, c_proj);

    const fla_f32x4 proj_even =
        fla_make_gemm0_projection_v4(c_proj[0], lane_g);
    const fla_f32x4 proj_odd =
        fla_make_gemm0_projection_v4(c_proj[1], lane_g);
    // c_proj[0]/[1] come from v_n=0/1 (even/odd V columns); u_lo/u_hi and
    // v_new store expect contiguous V8 {0,1,2,3,4,5,6,7}.
    const fla_f32x4 proj_lo = {
        proj_even[0], proj_odd[0], proj_even[1], proj_odd[1]};
    const fla_f32x4 proj_hi = {
        proj_even[2], proj_odd[2], proj_even[3], proj_odd[3]};

    // G was issued before U/K above; draining down to kUCnt + kKPrefetchCnt
    // proves it is ready while U and K direct-to-LDS keep running.
    if constexpr (FullChunk && Use_G) {
        wait_vmcnt<kYoungerThanRowGAfterGemm0Vmem>();
    } else if constexpr (!FullChunk && (Use_G || Use_GK)) {
        wait_all_and_barrier();
    }

    // row_scale consumes G (already waited above).  GK is issued right
    // after the h-snapshot store so it can overlap residual/v_tile/v_new
    // work; its explicit wait is deferred to the state-scale block.
    float row_scale = 1.0f;
    if constexpr (Use_G) {
        const float g_last = ck_tile::bit_cast<float>(row_g_last_bits);
        const float g_cur = ck_tile::bit_cast<float>(row_g_cur_bits);
        row_scale = fla_exp<Use_safe_exp, Use_exp2>(g_last - g_cur);
    }

    // h_low is already published and read by GEMM0; the snapshot is a plain
    // ds_read(h_low) -> buffer_store(GMEM) with no extra sync needed.
    fla_store_h_snapshot_swizzled_bv32<
        Element, Params, index_t, BV, BK, Kernel_traits::kThreads>(
        params, chunk, v_begin, h_low_tile, h_ptr, tid);

    if constexpr (PrefetchNextW) {
        // W_next: issue after h-snapshot so it overlaps GK/residual/GEMM1.
        const bool next_valid_row = t_local < next_valid_t;
        fla_load_w_tile_bv32_vgpr<Element, index_t, BK>(
            w_ptr, index_t(t_begin + BT), params.w_row_stride, next_valid_row,
            w_tensor_elems, w_carried);
    }

    // GK: issued after h-snapshot so it is younger than U in the VMEM queue.
    if constexpr (Use_GK) {
        const int32_t state_gk0_offset_bytes =
            static_cast<int32_t>(
                (index_t(last_idx) * params.gk_row_stride + k0) *
                sizeof(float));
        const int32_t state_gk1_offset_bytes =
            static_cast<int32_t>(
                (index_t(last_idx) * params.gk_row_stride + k1) *
                sizeof(float));
        state_gk0_bits =
            fla_buffer_load_vgpr<1>(gk_ptr, state_gk0_offset_bytes);
        state_gk1_bits =
            fla_buffer_load_vgpr<1>(gk_ptr, state_gk1_offset_bytes);
    }

    // Steady chunks: drain only U here, leaving K direct-to-LDS, h-snapshot,
    // and GK outstanding so K D2L overlaps residual/v_tile/v_new.  Tail keeps
    // the conservative full drain because partial valid_t changes the proof.
    if constexpr (FullChunk) {
        wait_vmcnt<kYoungerThanRawUAtResidualVmem>();
    } else {
        wait_all_and_barrier();
    }
    const ElementVec4 u_lo = fla_vec4_from_pack<Element>(u_pack, 0);
    const ElementVec4 u_hi = fla_vec4_from_pack<Element>(u_pack, 4);

    fla_f32x4 raw_lo = {
        ck_tile::type_convert<float>(u_lo[0]) - proj_lo[0],
        ck_tile::type_convert<float>(u_lo[1]) - proj_lo[1],
        ck_tile::type_convert<float>(u_lo[2]) - proj_lo[2],
        ck_tile::type_convert<float>(u_lo[3]) - proj_lo[3]};
    fla_f32x4 raw_hi = {
        ck_tile::type_convert<float>(u_hi[0]) - proj_hi[0],
        ck_tile::type_convert<float>(u_hi[1]) - proj_hi[1],
        ck_tile::type_convert<float>(u_hi[2]) - proj_hi[2],
        ck_tile::type_convert<float>(u_hi[3]) - proj_hi[3]};
    if (!valid_row) {
        raw_lo = fla_f32x4{0.0f, 0.0f, 0.0f, 0.0f};
        raw_hi = fla_f32x4{0.0f, 0.0f, 0.0f, 0.0f};
    }

    fla_f32x4 saved_lo = raw_lo;
    fla_f32x4 saved_hi = raw_hi;
    if constexpr (Use_G) {
        if constexpr (FullChunk) {
            fla_scale_v4_pairs(raw_lo, row_scale);
            fla_scale_v4_pairs(raw_hi, row_scale);
        } else if (valid_row) {
            fla_scale_v4_pairs(raw_lo, row_scale);
            fla_scale_v4_pairs(raw_hi, row_scale);
        } else {
            raw_lo = fla_f32x4{0.0f, 0.0f, 0.0f, 0.0f};
            raw_hi = fla_f32x4{0.0f, 0.0f, 0.0f, 0.0f};
        }
    }

    fla_store_v_tile_m32x16_bv32_swizzled<Element>(
        v_tile, t_local, raw_lo, raw_hi, lane_g);

    if constexpr (Save_new_value) {
        const fla_f32x4 store_lo = Use_G ? saved_lo : raw_lo;
        const fla_f32x4 store_hi = Use_G ? saved_hi : raw_hi;
        const int v_col_base = v_begin + lane_g * 8;
        const int32_t v_new_offset_bytes = static_cast<int32_t>(
            (index_t(t_begin + t_local) * params.v_new_row_stride +
             v_col_base) *
            sizeof(Element));
        compiler_sched_barrier();
        fla_buffer_store_element_v8_vgpr<Element>(
            v_new_ptr,
            valid_row ? v_new_offset_bytes : -1,
            store_lo, store_hi);
    }

    // GEMM1 publication: drain K direct-to-LDS VMEM (vmcnt) and publish
    // k_lds + v_tile LDS writes across all waves (lgkmcnt(0)+s_barrier).
    // Younger h-snapshot / GK / v_new GMEM ops stay outstanding; GK is
    // waited before state-scale, v_new at chunk exit.  K D2L must complete
    // before ds_read — lgkmcnt(0)+barrier alone is not enough.
    if constexpr (FullChunk) {
        wait_vmcnt_lgkmcnt0_barrier<kYoungerThanKAtGemm1Vmem>();
    } else {
        wait_all_and_barrier();
    }

    // 2. GEMM1: K from LDS (D2L + ds_read_alt), V from swizzled v_tile.
    fla_f32x4 c00 = {0.0f, 0.0f, 0.0f, 0.0f};
    fla_f32x4 c01 = {0.0f, 0.0f, 0.0f, 0.0f};
    fla_f32x4 c10 = {0.0f, 0.0f, 0.0f, 0.0f};
    fla_f32x4 c11 = {0.0f, 0.0f, 0.0f, 0.0f};
    const int gemm1_stages = FullChunk ? 4 : (valid_t + 15) / 16;
    for (int t_stage = 0; t_stage < gemm1_stages; ++t_stage) {
        const fla_u32x4 k_pack =
            fla_read_k_stage_alt<Element, BT, BK, Kernel_traits::kNWarps>(
                k_lds_tile, t_stage);
        const fla_u32x4 v_pack =
            fla_read_v_stage_m32x16<Element, BT, V_TILE_STRIDE>(
                v_tile, t_stage);
        const ElementVec4 a0 = fla_vec4_from_pack<Element>(v_pack, 0);
        const ElementVec4 a1 = fla_vec4_from_pack<Element>(v_pack, 4);
        const ElementVec4 b0 = fla_vec4_from_pack<Element>(k_pack, 0);
        const ElementVec4 b1 = fla_vec4_from_pack<Element>(k_pack, 4);
        c00 = fla_mmac_f32_16x16x16_trans_c<Element>(a0, b0, c00);
        c01 = fla_mmac_f32_16x16x16_trans_c<Element>(a0, b1, c01);
        c10 = fla_mmac_f32_16x16x16_trans_c<Element>(a1, b0, c10);
        c11 = fla_mmac_f32_16x16x16_trans_c<Element>(a1, b1, c11);
    }

    float state_scale_k0 = 1.0f;
    float state_scale_k1 = 1.0f;
    if constexpr (Use_G) {
        const float g_last =
            ck_tile::bit_cast<float>(row_g_last_bits);
        const float common_scale = fla_exp<false, Use_exp2>(g_last);
        state_scale_k0 = common_scale;
        state_scale_k1 = common_scale;
    }
    if constexpr (Use_GK) {
        // GK was issued after the h-snapshot store and is younger than U,
        // so the U wait left it outstanding.  Drain GK (and the equally
        // young h-snapshot stores) here, leaving only the optional v_new
        // store outstanding for the chunk-exit wait below.
        wait_vmcnt<kVNewStoreCnt>();
        state_scale_k0 *= fla_exp<false, Use_exp2>(
            ck_tile::bit_cast<float>(state_gk0_bits));
        state_scale_k1 *= fla_exp<false, Use_exp2>(
            ck_tile::bit_cast<float>(state_gk1_bits));
    }

#pragma unroll
    for (int s = 0; s < 4; ++s) {
        const fla_f32x2 delta = {c00[s], c01[s]};
        state_reg[s] = {
            state_reg[s][0] * state_scale_k0 + delta[0],
            state_reg[s][1] * state_scale_k1 + delta[1]};
    }
#pragma unroll
    for (int s = 0; s < 4; ++s) {
        const fla_f32x2 delta = {c10[s], c11[s]};
        state_reg[s + 4] = {
            state_reg[s + 4][0] * state_scale_k0 + delta[0],
            state_reg[s + 4][1] * state_scale_k1 + delta[1]};
    }
    fla_store_h_low_state_reg_swizzled_bv32<Element>(
        h_low_tile, lane_g, k0, state_reg);
    // Full-chunk exit: publish H1 for the next chunk and prove W_next is in
    // VGPR, but keep the independent v_new GMEM store in flight so it can
    // overlap the next chunk's GEMM0/prologue work.  Tail chunks keep the
    // conservative full drain because they are the terminal path.
    if constexpr (FullChunk) {
        wait_vmcnt_lgkmcnt0_barrier<kVNewStoreCnt>();
    } else {
        wait_all_and_barrier();
    }
}


// -----------------------------------------------------------------------------------------------
// gfx938 BV64 LDS32 path.
//
// Four waves are distributed over BV (one V16 slice per wave).  Every lane
// owns one V column and one interleaved BK8 fragment in each BK32 block:
//
//   state_even[e] = state[v, 32*bk + 8*q + 2*e]
//   state_odd[e]  = state[v, 32*bk + 8*q + 2*e + 1]
//
// These FP32 fragments remain authoritative across chunks.  GEMM0 creates its
// BF16 BK8 operand by lane-local source selection during conversion; GEMM1
// updates the same even/odd registers with LIT+LTS.  State conversion itself
// needs no ds_bpermute; the row-XOR U path below uses two per T16 stage to
// distribute a conflict-free q-even V8 read back to full-EXEC V4 ownership.
// -----------------------------------------------------------------------------------------------

template <typename Element>
__device__ __forceinline__ fla_u32x4
fla_pack_state_bk8_bv64(const fla_f32x4 even, const fla_f32x4 odd)
{
    return fla_u32x4{
        fla_pack_element_x2_bits<Element>(fla_f32x2{even[0], odd[0]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{even[1], odd[1]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{even[2], odd[2]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{even[3], odd[3]}),
    };
}

template <typename Element>
__device__ __forceinline__ void
fla_unpack_state_bk8_bv64(const fla_u32x4 raw, fla_f32x4 &even,
                          fla_f32x4 &odd)
{
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;
    const ElementVec4 lo = fla_vec4_from_pack<Element>(raw, 0);
    const ElementVec4 hi = fla_vec4_from_pack<Element>(raw, 4);
    even = fla_f32x4{
        ck_tile::type_convert<float>(lo[0]),
        ck_tile::type_convert<float>(lo[2]),
        ck_tile::type_convert<float>(hi[0]),
        ck_tile::type_convert<float>(hi[2])};
    odd = fla_f32x4{
        ck_tile::type_convert<float>(lo[1]),
        ck_tile::type_convert<float>(lo[3]),
        ck_tile::type_convert<float>(hi[1]),
        ck_tile::type_convert<float>(hi[3])};
}

// FP32 persistent state uses two dwordx4 loads for the same eight interleaved
// K values represented by one packed BF16/FP16 dwordx4 fragment.
__device__ __forceinline__ void
fla_unpack_state_bk8_bv64_fp32(const fla_u32x4 raw_lo,
                               const fla_u32x4 raw_hi,
                               fla_f32x4 &even, fla_f32x4 &odd)
{
    const fla_f32x4 lo = ck_tile::bit_cast<fla_f32x4>(raw_lo);
    const fla_f32x4 hi = ck_tile::bit_cast<fla_f32x4>(raw_hi);
    even = fla_f32x4{lo[0], lo[2], hi[0], hi[2]};
    odd = fla_f32x4{lo[1], lo[3], hi[1], hi[3]};
}

// The HCU raw-buffer descriptor path is reliable for the packed BF16 state,
// but the FP32 BV64 path can miscompile a long sequence of dwordx4 buffer
// accesses.  FP32 state is dense in its H/V/K dimensions, so use ordinary
// aligned global vector accesses for this fallback.  This helper is limited
// to the BV64 FP32 state path and does not change the BF16 hot path.
__device__ __forceinline__ fla_u32x4
fla_load_state_fp32x4_direct(const float *__restrict__ ptr)
{
    return ck_tile::bit_cast<fla_u32x4>(
        *reinterpret_cast<const fla_f32x4 *>(ptr));
}

__device__ __forceinline__ void
fla_store_state_fp32x4_direct(float *__restrict__ ptr,
                              const fla_u32x4 value)
{
    *reinterpret_cast<fla_f32x4 *>(ptr) = ck_tile::bit_cast<fla_f32x4>(value);
}

template <int Half, typename Element>
__device__ __forceinline__ typename fla_dtype_traits<Element>::vec4_t
fla_make_gemm0_state_operand_bv64(const fla_f32x4 even,
                                   const fla_f32x4 odd)
{
    static_assert(Half == 0 || Half == 1, "BK8 has two BF16x4 halves");
    constexpr int e = Half * 2;
    return fla_pack_f32x4_to_element_vec4<Element>(
        fla_f32x4{even[e], odd[e], even[e + 1], odd[e + 1]});
}

template <typename Kernel_traits, typename Params>
__device__ __forceinline__ void
fla_store_h_snapshot_bk_bv64_packed(
    const Params &params, const int chunk, const int v_begin, const int bk,
    typename Kernel_traits::Element *__restrict__ h_ptr,
    const typename fla_dtype_traits<
        typename Kernel_traits::Element>::vec4_t state_lo,
    const typename fla_dtype_traits<
        typename Kernel_traits::Element>::vec4_t state_hi)
{
    using Element = typename Kernel_traits::Element;
    using index_t = typename Kernel_traits::index_t;
    const fla_u32x2 lo = ck_tile::bit_cast<fla_u32x2>(state_lo);
    const fla_u32x2 hi = ck_tile::bit_cast<fla_u32x2>(state_hi);
    const fla_u32x4 packed = {lo[0], lo[1], hi[0], hi[1]};

    const int warp_id = threadIdx.x / 64;
    const int lane_id = threadIdx.x & 63;
    const int p = lane_id & 15;
    const int q = lane_id >> 4;
    const int v_col = v_begin + warp_id * 16 + p;
    const int32_t offset = static_cast<int32_t>(
        (index_t(chunk) * params.h_chunk_stride +
         index_t(v_col) * params.K + bk * 32 + q * 8) *
        sizeof(Element));
    fla_buffer_store_vgpr<4>(h_ptr, v_col < params.V ? offset : -1,
                             packed);
}

template <int BkBegin, int BkEnd, typename Kernel_traits, typename Params>
__device__ __forceinline__ void
fla_gemm0_bv64_lit_range(
    typename Kernel_traits::Element *__restrict__ w_lds,
    const fla_f32x4 (&state_even)[4],
    const fla_f32x4 (&state_odd)[4],
    fla_f32x4 (&projection)[4], const Params &params, const int chunk,
    const int v_begin,
    typename Kernel_traits::Element *__restrict__ h_ptr)
{
    using Element = typename Kernel_traits::Element;
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;
    static_assert(BkBegin >= 0 && BkBegin < BkEnd && BkEnd <= 4,
                  "invalid BV64 GEMM0 BK range");

#pragma unroll
    for (int bk = BkBegin; bk < BkEnd; ++bk) {
        const ElementVec4 state_lo =
            fla_make_gemm0_state_operand_bv64<0, Element>(
                state_even[bk], state_odd[bk]);
        const ElementVec4 state_hi =
            fla_make_gemm0_state_operand_bv64<1, Element>(
                state_even[bk], state_odd[bk]);
#pragma unroll
        for (int t_stage = 0; t_stage < 4; ++t_stage) {
            const fla_u32x4 w_pack =
                fla_read_w_stage_bv64<Element, 64, 128, 4>(
                    w_lds, t_stage, bk);
            const ElementVec4 w_lo =
                fla_vec4_from_pack<Element>(w_pack, 0);
            const ElementVec4 w_hi =
                fla_vec4_from_pack<Element>(w_pack, 4);
            projection[t_stage] =
                fla_mmac_f32_16x16x16_lit<Element>(
                    w_lo, state_lo, projection[t_stage]);
            projection[t_stage] =
                fla_mmac_f32_16x16x16_lit<Element>(
                    w_hi, state_hi, projection[t_stage]);
        }
        fla_store_h_snapshot_bk_bv64_packed<Kernel_traits>(
            params, chunk, v_begin, bk, h_ptr, state_lo, state_hi);
    }
}

template <typename Kernel_traits, typename Params>
__device__ __forceinline__ void
fla_store_final_state_bv64_vgpr(
    const Params &params, const int v_begin,
    typename Kernel_traits::State *__restrict__ ht_ptr,
    const fla_f32x4 (&state_even)[4],
    const fla_f32x4 (&state_odd)[4])
{
    using State = typename Kernel_traits::State;
    using index_t = typename Kernel_traits::index_t;

    const int warp_id = threadIdx.x / 64;
    const int lane_id = threadIdx.x & 63;
    const int p = lane_id & 15;
    const int q = lane_id >> 4;
    const int v_col = v_begin + warp_id * 16 + p;

#pragma unroll
    for (int bk = 0; bk < 4; ++bk) {
        const int32_t offset = static_cast<int32_t>(
            (index_t(v_col) * params.K + bk * 32 + q * 8) *
            sizeof(State));
        const int32_t voffset = v_col < params.V ? offset : -1;
        if constexpr (std::is_same_v<State, float>) {
            const fla_u32x4 packed_lo = ck_tile::bit_cast<fla_u32x4>(
                fla_f32x4{state_even[bk][0], state_odd[bk][0],
                          state_even[bk][1], state_odd[bk][1]});
            const fla_u32x4 packed_hi = ck_tile::bit_cast<fla_u32x4>(
                fla_f32x4{state_even[bk][2], state_odd[bk][2],
                          state_even[bk][3], state_odd[bk][3]});
            if (v_col < params.V) {
                fla_store_state_fp32x4_direct(ht_ptr +
                                                  index_t(v_col) * params.K +
                                                  bk * 32 + q * 8,
                                              packed_lo);
                fla_store_state_fp32x4_direct(
                    ht_ptr + index_t(v_col) * params.K + bk * 32 + q * 8 + 4,
                    packed_hi);
            }
        } else {
            const fla_u32x4 packed =
                fla_pack_state_bk8_bv64<State>(state_even[bk], state_odd[bk]);
            fla_buffer_store_vgpr<4>(ht_ptr, voffset, packed);
        }
    }
}

template <typename Index>
__device__ __forceinline__ void
fla_prefetch_g_chunk_bv64(
    const float *__restrict__ g_ptr, const Index g_row_stride,
    const int t_begin, const int valid_t, uint32_t &g_last_bits,
    uint32_t (&g_cur_bits)[4])
{
    const int p = threadIdx.x & 15;
    const int q = (threadIdx.x & 63) >> 4;
    // g[last] is one of the four g_cur stages.  Recover it after the VMEM
    // publication wait with a wave readlane instead of issuing a fifth load.
    g_last_bits = 0;

#pragma unroll
    for (int t_stage = 0; t_stage < 4; ++t_stage) {
        const int t_local = t_stage * 16 + p;
        const int32_t offset = static_cast<int32_t>(
            Index(t_begin + t_local) * g_row_stride * sizeof(float));
        // One 16-lane group loads each scalar gate.  All q groups need the
        // same value, so the following ds_bpermute broadcasts q=0 to the
        // remaining groups without extra global loads.
        g_cur_bits[t_stage] = (q == 0)
            ? fla_buffer_load_vgpr<1>(
                  g_ptr, t_local < valid_t ? offset : -1)
            : 0;
    }
}

__device__ __forceinline__ void
fla_broadcast_g_cur_bv64(uint32_t (&g_cur_bits)[4])
{
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    const int p = threadIdx.x & 15;
    // The builtin lowers to ds_bpermute_b32 and carries its LGKM data
    // dependency to LLVM.  Leave wait placement to the compiler so the four
    // independent broadcasts can overlap with the following VALU work.
    uint32_t g0 = fla_ds_bpermute_u32(p << 2, g_cur_bits[0]);
    uint32_t g1 = fla_ds_bpermute_u32(p << 2, g_cur_bits[1]);
    uint32_t g2 = fla_ds_bpermute_u32(p << 2, g_cur_bits[2]);
    uint32_t g3 = fla_ds_bpermute_u32(p << 2, g_cur_bits[3]);
    g_cur_bits[0] = g0;
    g_cur_bits[1] = g1;
    g_cur_bits[2] = g2;
    g_cur_bits[3] = g3;
#else
    (void)g_cur_bits;
#endif
}

template <bool FullChunk>
__device__ __forceinline__ uint32_t
fla_recover_g_last_bits_bv64(const int valid_t,
                             const uint32_t (&g_cur_bits)[4])
{
    uint32_t source_bits;
    int source_lane;
    if constexpr (FullChunk) {
        source_bits = g_cur_bits[3];
        source_lane = 15;
    } else {
        const int last_local = valid_t - 1;
        source_lane = last_local & 15;
        switch (last_local >> 4) {
        case 0:
            source_bits = g_cur_bits[0];
            break;
        case 1:
            source_bits = g_cur_bits[1];
            break;
        case 2:
            source_bits = g_cur_bits[2];
            break;
        default:
            source_bits = g_cur_bits[3];
            break;
        }
    }
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    return static_cast<uint32_t>(__builtin_amdgcn_readlane(
        static_cast<int32_t>(source_bits), source_lane));
#else
    return source_bits;
#endif
}

template <typename Index>
__device__ __forceinline__ fla_u32x2
fla_prefetch_gk_pair_bv64(const float *__restrict__ gk_ptr,
                          const Index gk_row_stride, const int last_idx)
{
    // Across a wave, lane 0..63 cover the complete contiguous K128 row as
    // float2 fragments. This keeps the public GK layout unchanged while
    // replacing four BK-local sparse load/wait groups with one coalesced VMEM
    // instruction whose latency can overlap the residual-V path.
    const int lane_id = threadIdx.x & 63;
    const int32_t offset = static_cast<int32_t>(
        (Index(last_idx) * gk_row_stride + lane_id * 2) * sizeof(float));
    return fla_buffer_load_vgpr<2>(gk_ptr, offset);
}

__device__ __forceinline__ void
fla_scale_state_bk8_gk_bv64(const fla_f32x2 gk_scale_pair,
                            const int bk, const int q,
                            fla_f32x4 &state_even, fla_f32x4 &state_odd)
{
    // Lane s owns exp(GK[2*s:2*s+2]). A destination lane owns K8 at
    // BK32 + q*8, so four per-lane bpermute addresses gather its even/odd
    // factors from lanes bk*16 + q*4 + [0, 4). Unlike readlane, bpermute
    // supports a lane-varying source address and therefore preserves all four
    // q fragments.
    const uint32_t scale_even_bits =
        ck_tile::bit_cast<uint32_t>(gk_scale_pair[0]);
    const uint32_t scale_odd_bits =
        ck_tile::bit_cast<uint32_t>(gk_scale_pair[1]);
    fla_f32x4 scale_even;
    fla_f32x4 scale_odd;
#pragma unroll
    for (int i = 0; i < 4; ++i) {
        const int source_lane = bk * 16 + q * 4 + i;
        scale_even[i] = ck_tile::bit_cast<float>(
            fla_ds_bpermute_u32(source_lane * sizeof(uint32_t),
                                scale_even_bits));
        scale_odd[i] = ck_tile::bit_cast<float>(
            fla_ds_bpermute_u32(source_lane * sizeof(uint32_t),
                                scale_odd_bits));
    }

    // Keep the scale application register-only and use the same packed FP32
    // multiply primitive as the common G scale. This halves the VALU issue
    // count without changing state ownership or representation.
    const fla_f32x2 even_lo = fla_pk_mul_f32(
        fla_f32x2{state_even[0], state_even[1]},
        fla_f32x2{scale_even[0], scale_even[1]});
    const fla_f32x2 even_hi = fla_pk_mul_f32(
        fla_f32x2{state_even[2], state_even[3]},
        fla_f32x2{scale_even[2], scale_even[3]});
    state_even = fla_f32x4{even_lo[0], even_lo[1], even_hi[0], even_hi[1]};

    const fla_f32x2 odd_lo = fla_pk_mul_f32(
        fla_f32x2{state_odd[0], state_odd[1]},
        fla_f32x2{scale_odd[0], scale_odd[1]});
    const fla_f32x2 odd_hi = fla_pk_mul_f32(
        fla_f32x2{state_odd[2], state_odd[3]},
        fla_f32x2{scale_odd[2], scale_odd[3]});
    state_odd = fla_f32x4{odd_lo[0], odd_lo[1], odd_hi[0], odd_hi[1]};
}

template <typename Kernel_traits, typename Params, bool FullChunk,
          bool PrefetchNextW>
__device__ __forceinline__ void
run_chunk_gated_delta_rule_fwd_chunk_bv64_lds32(
    const Params &params, const int chunk, const int t_begin,
    const int valid_t, const int last_idx, const int v_begin,
    const typename Kernel_traits::Element *__restrict__ k_ptr,
    const typename Kernel_traits::Element *__restrict__ w_ptr,
    const typename Kernel_traits::Element *__restrict__ u_ptr,
    typename Kernel_traits::Element *__restrict__ h_ptr,
    typename Kernel_traits::Element *__restrict__ v_new_ptr,
    const float *__restrict__ g_ptr,
    const float *__restrict__ gk_ptr,
    uint32_t &g_last_bits, uint32_t (&g_cur_bits)[4],
    fla_f32x4 (&state_even)[4], fla_f32x4 (&state_odd)[4],
    typename Kernel_traits::Element *__restrict__ w_uv_lds,
    typename Kernel_traits::Element *__restrict__ k_lds,
    const int next_valid_t = Kernel_traits::kBlockT)
{
    using Element = typename Kernel_traits::Element;
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;
    using index_t = typename Kernel_traits::index_t;

    constexpr int BT = Kernel_traits::kBlockT;
    constexpr int BK = Kernel_traits::kBlockK;
    constexpr bool Use_G = Kernel_traits::Use_G;
    constexpr bool Use_GK = Kernel_traits::Use_GK;
    constexpr bool Use_exp2 = Kernel_traits::Use_exp2;
    constexpr bool Use_safe_exp = Kernel_traits::Use_safe_exp;
    static_assert(BT == 64 && BK == 128 && Kernel_traits::kBlockV == 64,
                  "BV64 LDS32 chunk requires BT64/BK128/BV64");
    static_assert(!PrefetchNextW || FullChunk,
                  "only a full non-last chunk may prefetch W_next");

    if constexpr (!FullChunk) {
        if (valid_t <= 0 || last_idx < 0) {
            return;
        }
    }

    const int lane_id = threadIdx.x & 63;
    const int p = lane_id & 15;
    const int q = lane_id >> 4;

    // The compact G prefetch issues four VMEM loads per wave.  With G enabled,
    // publish W while leaving those four requests in flight; without G, W is
    // the only carried LDS publication in this age group.
    if constexpr (Use_G) {
        wait_vmcnt_lgkmcnt0_barrier<4>();
    } else {
        wait_vmcnt_lgkmcnt0_barrier<0>();
    }

    fla_f32x4 projection[4] = {
        {0.0f, 0.0f, 0.0f, 0.0f},
        {0.0f, 0.0f, 0.0f, 0.0f},
        {0.0f, 0.0f, 0.0f, 0.0f},
        {0.0f, 0.0f, 0.0f, 0.0f}};

    // Consume BK[0:64].  Once every wave reaches the barrier the low 8 KiB
    // of W is dead and may be overwritten by the T64xV64 U image.  The
    // already-created state packs are also used for BK0/BK1 h stores here.
    fla_gemm0_bv64_lit_range<0, 2, Kernel_traits>(
        w_uv_lds, state_even, state_odd, projection,
        params, chunk, v_begin, h_ptr);
    wait_lgkmcnt0_barrier();

    const Element *__restrict__ u_chunk =
        u_ptr + index_t(t_begin) * params.u_row_stride + v_begin;
    // The following VMEM age proof requires U0/U1 before K0..K3.
    compiler_sched_barrier();
    if constexpr (FullChunk) {
        fla_prefetch_u_t32_v64_to_lds<Element, index_t, false>(
            w_uv_lds, u_chunk, params.u_row_stride, 0, BT);
        fla_prefetch_u_t32_v64_to_lds<Element, index_t, false>(
            w_uv_lds + 32 * 64, u_chunk, params.u_row_stride, 32, BT);
        compiler_sched_barrier();
        fla_prefetch_k_to_lds<Element, BT, BK, Kernel_traits::kNWarps,
                              false>(
            k_lds, k_ptr + index_t(t_begin) * params.k_row_stride,
            params.k_row_stride, BT);
    } else {
        fla_prefetch_u_t32_v64_to_lds<Element, index_t, true>(
            w_uv_lds, u_chunk, params.u_row_stride, 0, valid_t);
        fla_prefetch_u_t32_v64_to_lds<Element, index_t, true>(
            w_uv_lds + 32 * 64, u_chunk, params.u_row_stride, 32, valid_t);
        compiler_sched_barrier();
        fla_prefetch_k_to_lds<Element, BT, BK, Kernel_traits::kNWarps,
                              true>(
            k_lds, k_ptr + index_t(t_begin) * params.k_row_stride,
            params.k_row_stride, valid_t);
    }
    compiler_sched_barrier();

    // U is older than K.  GEMM0 high emits two h stores younger than the four
    // K D2L operations, so vmcnt(6) publishes U/G while leaving K+h_high in
    // flight.
    fla_gemm0_bv64_lit_range<2, 4, Kernel_traits>(
        w_uv_lds, state_even, state_odd, projection,
        params, chunk, v_begin, h_ptr);
    wait_vmcnt_lgkmcnt0_barrier<6>();

    fla_u32x2 gk_pair_bits = {0, 0};
    if constexpr (Use_GK) {
        // K and the two high-h stores are the only older VMEM operations here.
        // Keep this single wave-wide GK load older than residual stores and the
        // next-chunk W/G prefetches so a partial wait can publish K+GK without
        // draining the carried W/G group.
        compiler_sched_barrier();
        gk_pair_bits = fla_prefetch_gk_pair_bv64<index_t>(
            gk_ptr, params.gk_row_stride, last_idx);
        compiler_sched_barrier();
    }

    float state_scale = 1.0f;
    float row_scale[4] = {1.0f, 1.0f, 1.0f, 1.0f};
    if constexpr (Use_G) {
        fla_broadcast_g_cur_bv64(g_cur_bits);
        g_last_bits =
            fla_recover_g_last_bits_bv64<FullChunk>(valid_t, g_cur_bits);
        const float g_last = ck_tile::bit_cast<float>(g_last_bits);
        state_scale = fla_exp<false, Use_exp2>(g_last);
#pragma unroll
        for (int t_stage = 0; t_stage < 4; ++t_stage) {
            const float g_cur = ck_tile::bit_cast<float>(g_cur_bits[t_stage]);
            row_scale[t_stage] =
                fla_exp<Use_safe_exp, Use_exp2>(g_last - g_cur);
        }
    }

    // Consume the four independent 2-KiB U regions.  Padded V stages 0..2 go
    // to dead high-W storage, so their U bpermutes need only an lgkmcnt wait.
    // Stage 3 synchronizes the CTA before its V output reuses low LDS; at that
    // point every wave has consumed every U stage.  Tail lanes still execute
    // every LDS/MMAC instruction.
    const int v_store_lane_offset = fla_v_store_lane_offset_m32x16_bv64();
#pragma unroll
    for (int t_stage = 0; t_stage < 4; ++t_stage) {
        const int t_local = t_stage * 16 + p;
        const bool valid_row = FullChunk || t_local < valid_t;
        const fla_u32x2 u_pack =
            fla_read_u_v4_d2l_bv64<Element>(w_uv_lds, t_stage,
                                            t_stage == 3);

        const ElementVec4 u_v4 = ck_tile::bit_cast<ElementVec4>(u_pack);
        fla_f32x4 raw = {
            ck_tile::type_convert<float>(u_v4[0]) - projection[t_stage][0],
            ck_tile::type_convert<float>(u_v4[1]) - projection[t_stage][1],
            ck_tile::type_convert<float>(u_v4[2]) - projection[t_stage][2],
            ck_tile::type_convert<float>(u_v4[3]) - projection[t_stage][3]};
        if (!valid_row) {
            raw = fla_f32x4{0.0f, 0.0f, 0.0f, 0.0f};
        }
        const fla_f32x4 v_new = raw;
        if constexpr (Use_G) {
          if (valid_row) {
            fla_scale_v4_pairs(raw, row_scale[t_stage]);
          }
        }
        fla_store_v_v4_m32x16_bv64<Element>(
            w_uv_lds, t_stage, v_store_lane_offset, raw);

        if constexpr (Kernel_traits::Save_new_value) {
            const int warp_id = threadIdx.x / 64;
            const int v_col = v_begin + warp_id * 16 + q * 4;
            const int32_t offset = static_cast<int32_t>(
                (index_t(t_begin + t_local) * params.v_new_row_stride + v_col) *
                sizeof(Element));
            fla_buffer_store_element_v4_vgpr<Element>(
                v_new_ptr, valid_row ? offset : -1,
                fla_f32x2{v_new[0], v_new[1]},
                fla_f32x2{v_new[2], v_new[3]});
        }
    }

    // Publish the final V stores, then pull all four matrix fragments into
    // VGPR before W_next overwrites the shared W/U/V allocation.
    wait_lgkmcnt0_barrier();
    fla_u32x4 v_raw[4];
    const int v_read_lane_offset = fla_v_read_lane_offset_m32x16_bv64();
#pragma unroll
    for (int t_stage = 0; t_stage < 4; ++t_stage) {
        v_raw[t_stage] =
            fla_read_v_t16_v32_m32x16_bv64<Element>(
                w_uv_lds, t_stage, v_read_lane_offset);
    }
    fla_lds_barrier();

    ElementVec4 v_operand[4];
    const int v_half = (threadIdx.x / 64) & 1;
#pragma unroll
    for (int t_stage = 0; t_stage < 4; ++t_stage) {
        // Both source offsets must remain compile-time constants.  Passing a
        // runtime 0/4 index to fla_vec4_from_pack materializes the vector in
        // private memory and creates scratch buffer traffic.
        const ElementVec4 v_lo =
            fla_vec4_from_pack<Element>(v_raw[t_stage], 0);
        const ElementVec4 v_hi =
            fla_vec4_from_pack<Element>(v_raw[t_stage], 4);
        v_operand[t_stage] = v_half ? v_hi : v_lo;
    }

    if constexpr (PrefetchNextW) {
        compiler_sched_barrier();
        fla_prefetch_w_to_lds<Element, BT, BK, Kernel_traits::kNWarps, true>(
            w_uv_lds,
            w_ptr + index_t(t_begin + BT) * params.w_row_stride,
            params.w_row_stride, next_valid_t);
        compiler_sched_barrier();
        // G_next is deliberately younger than W_next.  The next chunk can
        // publish W while these loads continue in flight.
        if constexpr (Use_G) {
            fla_prefetch_g_chunk_bv64<index_t>(
                g_ptr, params.g_row_stride, t_begin + BT, next_valid_t,
                g_last_bits, g_cur_bits);
            compiler_sched_barrier();
        }
    }

    // BK2/BK3 h stores are older than K. The optional wave-wide GK load is
    // younger than both, but older than residual stores, W_next, and compact
    // G_next. With GK enabled, publish both K and GK while retaining only those
    // younger operations; without GK, retain the established high-h stores as
    // well. All counts remain compile-time constants for each specialization.
    constexpr int kHighHSnapshotCnt = 2;
    constexpr int kVNewStoreCnt = Kernel_traits::Save_new_value ? 4 : 0;
    constexpr int kWNextCnt = PrefetchNextW ? 4 : 0;
    constexpr int kGNextCnt = PrefetchNextW && Use_G ? 4 : 0;
    if constexpr (Use_GK) {
        wait_vmcnt_barrier<kVNewStoreCnt + kWNextCnt + kGNextCnt>();
    } else {
        wait_vmcnt_barrier<kHighHSnapshotCnt + kVNewStoreCnt +
                           kWNextCnt + kGNextCnt>();
    }

    fla_f32x2 gk_scale_pair = {1.0f, 1.0f};
    if constexpr (Use_GK) {
        const fla_f32x2 gk_pair = ck_tile::bit_cast<fla_f32x2>(gk_pair_bits);
        gk_scale_pair = fla_f32x2{
            fla_exp<false, Use_exp2>(gk_pair[0]),
            fla_exp<false, Use_exp2>(gk_pair[1])};
    }

    // GEMM1 updates one BK32 state fragment at a time.  Alternate K reads
    // provide even/odd BK8 vectors; the normal V read already selected this
    // wave's BV16.  Both LIT and LTS remain enabled for every accumulation.
#pragma unroll
    for (int bk = 0; bk < 4; ++bk) {
        fla_scale_v4_pairs(state_even[bk], state_scale);
        fla_scale_v4_pairs(state_odd[bk], state_scale);
        if constexpr (Use_GK) {
            fla_scale_state_bk8_gk_bv64(
                gk_scale_pair, bk, q,
                state_even[bk], state_odd[bk]);
        }

        fla_u32x4 k_raw[4];
#pragma unroll
        for (int t_stage = 0; t_stage < 4; ++t_stage) {
            k_raw[t_stage] =
                fla_read_k_stage_alt_bv64<Element, BT, BK,
                                           Kernel_traits::kNWarps>(
                    k_lds, bk, t_stage);
        }
#pragma unroll
        for (int t_stage = 0; t_stage < 4; ++t_stage) {
            const ElementVec4 k_even =
                fla_vec4_from_pack<Element>(k_raw[t_stage], 0);
            const ElementVec4 k_odd =
                fla_vec4_from_pack<Element>(k_raw[t_stage], 4);
            state_even[bk] =
                fla_mmac_f32_16x16x16_lit_lts<Element>(
                    k_even, v_operand[t_stage], state_even[bk]);
            state_odd[bk] =
                fla_mmac_f32_16x16x16_lit_lts<Element>(
                    k_odd, v_operand[t_stage], state_odd[bk]);
        }
    }

    // Close the shared K read lifetime before the next chunk overwrites the
    // single K buffer.  W_next remains governed by the next chunk's entrance
    // VMEM wait.
    fla_lds_barrier();
}

template <typename Kernel_traits, typename Params>
__device__ void
run_chunk_gated_delta_rule_fwd_kernel_body_bv64_lds32(
    const Params &params, const int i_v, const int i_nh)
{
    using Element = typename Kernel_traits::Element;
    using State = typename Kernel_traits::State;
    using index_t = typename Kernel_traits::index_t;

    constexpr int BT = Kernel_traits::kBlockT;
    constexpr int BK = Kernel_traits::kBlockK;
    constexpr int BV = Kernel_traits::kBlockV;
    static_assert(BT == 64 && BK == 128 && BV == 64 &&
                      Kernel_traits::kNWarps == 4,
                  "gfx938 BV64 LDS32 path requires BT64/BK128/BV64/W4");
    static_assert(Kernel_traits::Transpose_state,
                  "gfx938 BV64 LDS32 path requires transpose state");
    static_assert(std::is_same_v<State, float> ||
                      std::is_same_v<State, ck_tile::bf16_t>,
                  "BV64 state must be FP32 or BF16");
    static_assert(Kernel_traits::w_smem_size == 16 * 1024 &&
                      Kernel_traits::k_smem_size == 16 * 1024 &&
                      Kernel_traits::v_tile_smem_size == 0 &&
                      Kernel_traits::h_low_smem_size == 0 &&
                      Kernel_traits::smem_size == 32 * 1024,
                  "BV64 LDS alias layout must be exactly W/UV16K + K16K");

    const int i_n = i_nh / params.H;
    const int i_h = i_nh - i_n * params.H;
    const int v_begin = i_v * BV;
    BlockInfo<Kernel_traits::Is_varlen,
              typename Kernel_traits::VarlenIndexT> binfo(params, i_n);
    const int nt = binfo.n_chunks();
    const int seqlen = binfo.actual_seqlen();
    const int h_per_k = params.H / params.Hg;

    const Element *__restrict__ k_ptr =
        reinterpret_cast<const Element *>(params.k_ptr) +
        binfo.template k_offset<index_t>(
            i_h, params.k_row_stride, params.k_head_stride, h_per_k);
    const Element *__restrict__ w_ptr =
        reinterpret_cast<const Element *>(params.w_ptr) +
        binfo.template w_offset<index_t>(
            i_h, params.w_row_stride, params.w_head_stride);
    const Element *__restrict__ u_ptr =
        reinterpret_cast<const Element *>(params.u_ptr) +
        binfo.template v_offset<index_t>(
            i_h, params.u_row_stride, params.u_head_stride);
    Element *__restrict__ h_ptr =
        reinterpret_cast<Element *>(params.h_ptr) +
        binfo.template h_offset<index_t>(
            i_h, params.h_chunk_stride, params.h_head_stride);
    Element *__restrict__ v_new_ptr = nullptr;
    if constexpr (Kernel_traits::Save_new_value) {
        v_new_ptr = reinterpret_cast<Element *>(params.v_new_ptr) +
                    binfo.template v_offset<index_t>(
                        i_h, params.v_new_row_stride,
                        params.v_new_head_stride);
    }
    const float *__restrict__ g_ptr = nullptr;
    if constexpr (Kernel_traits::Use_G) {
        g_ptr = reinterpret_cast<const float *>(params.g_ptr) +
                binfo.template g_offset<index_t>(i_h, params.g_row_stride);
    }
    const float *__restrict__ gk_ptr = nullptr;
    if constexpr (Kernel_traits::Use_GK) {
        gk_ptr = reinterpret_cast<const float *>(params.gk_ptr) +
                 binfo.template gk_offset<index_t>(
                     i_h, params.gk_row_stride, params.gk_head_stride);
    }

    const State *__restrict__ h0_ptr = nullptr;
    State *__restrict__ ht_ptr = nullptr;
    if constexpr (Kernel_traits::Use_initial_state) {
        if (binfo.has_state()) {
            h0_ptr = reinterpret_cast<const State *>(params.h0_ptr) +
                     binfo.template state_offset<index_t>(
                         i_h, params.h0_batch_stride, params.h0_head_stride);
        }
    }
    if constexpr (Kernel_traits::Store_final_state) {
        if (binfo.has_state()) {
            ht_ptr = reinterpret_cast<State *>(params.ht_ptr) +
                     binfo.template state_offset<index_t>(
                         i_h, params.ht_batch_stride, params.ht_head_stride);
        }
    }

    extern __shared__ uint8_t lds_base[];
    Element *w_uv_lds = reinterpret_cast<Element *>(lds_base);
    Element *k_lds = reinterpret_cast<Element *>(
        lds_base + Kernel_traits::w_smem_size);

    const int warp_id = threadIdx.x / 64;
    const int lane_id = threadIdx.x & 63;
    const int p = lane_id & 15;
    const int q = lane_id >> 4;
    const int v_col = v_begin + warp_id * 16 + p;

    uint32_t g_last_bits = 0;
    uint32_t g_cur_bits[4] = {};
    constexpr int kGLoadCnt = Kernel_traits::Use_G ? 4 : 0;

    // Coalesced BK8 initial-state loads match the persistent even/odd owner.
    // BF16 state packs eight values into one dwordx4; FP32 state needs two
    // dwordx4 loads for the same eight K values.  Both forms are decoded into
    // the same FP32 even/odd fragments before GEMM0.
    fla_u32x4 initial_raw[4] = {};
    fla_u32x4 initial_raw_hi[4] = {};
    if constexpr (Kernel_traits::Use_initial_state) {
      if (binfo.has_state()) {
        // Keep the ordinary FP32 state loads on the prefetch side of the
        // scheduler boundary.  Unlike the inline buffer-load path, a plain
        // vector dereference has no volatile asm boundary and LLVM may move
        // it across the following W/G prefetches or waitcnt.
        if constexpr (std::is_same_v<State, float>) {
            compiler_sched_barrier();
        }
#pragma unroll
        for (int bk = 0; bk < 4; ++bk) {
            const int32_t offset = static_cast<int32_t>(
                (index_t(v_col) * params.K + bk * 32 + q * 8) *
                sizeof(State));
            if constexpr (std::is_same_v<State, float>) {
                if (v_col < params.V) {
                    const float *state_ptr = h0_ptr +
                        index_t(v_col) * params.K + bk * 32 + q * 8;
                    initial_raw[bk] = fla_load_state_fp32x4_direct(state_ptr);
                    initial_raw_hi[bk] = fla_load_state_fp32x4_direct(
                        state_ptr + 4);
                }
            } else {
                initial_raw[bk] = fla_buffer_load_vgpr<4>(
                    h0_ptr, v_col < params.V ? offset : -1);
            }
        }
        if constexpr (std::is_same_v<State, float>) {
            compiler_sched_barrier();
        }
      }
    }

    const int last_chunk = nt - 1;
    const int last_t_begin = last_chunk * BT;
    const int last_valid_t = seqlen - last_t_begin;
    if (nt > 0) {
        const int chunk0_valid_t = nt == 1 ? last_valid_t : BT;
        // Keep the initial-state VMEM group ahead of the carried W/G groups
        // used by the prologue age model.
        compiler_sched_barrier();
        fla_prefetch_w_to_lds<Element, BT, BK, Kernel_traits::kNWarps, true>(
            w_uv_lds, w_ptr, params.w_row_stride, chunk0_valid_t);
        compiler_sched_barrier();
        if constexpr (Kernel_traits::Use_G) {
            fla_prefetch_g_chunk_bv64<index_t>(
                g_ptr, params.g_row_stride, 0, chunk0_valid_t,
                g_last_bits, g_cur_bits);
        }
        compiler_sched_barrier();
        // State loads are older than W0(4) and optional compact G0(4).
        // Publish only the state fragments and leave W/G outstanding.
        wait_vmcnt<4 + kGLoadCnt>();
    } else {
        wait_vmcnt<0>();
    }

    fla_f32x4 state_even[4];
    fla_f32x4 state_odd[4];
#pragma unroll
    for (int bk = 0; bk < 4; ++bk) {
        if constexpr (Kernel_traits::Use_initial_state) {
            if constexpr (std::is_same_v<State, float>) {
                fla_unpack_state_bk8_bv64_fp32(
                    initial_raw[bk], initial_raw_hi[bk],
                    state_even[bk], state_odd[bk]);
            } else {
                fla_unpack_state_bk8_bv64<State>(
                    initial_raw[bk], state_even[bk], state_odd[bk]);
            }
        } else {
            state_even[bk] = fla_f32x4{0.0f, 0.0f, 0.0f, 0.0f};
            state_odd[bk] = fla_f32x4{0.0f, 0.0f, 0.0f, 0.0f};
        }
    }

    if (nt >= 2) {
        const int next_valid_t = nt == 2 ? last_valid_t : BT;
        run_chunk_gated_delta_rule_fwd_chunk_bv64_lds32<
            Kernel_traits, Params, true, true>(
            params, 0, 0, BT, BT - 1, v_begin, k_ptr, w_ptr, u_ptr,
            h_ptr, v_new_ptr, g_ptr, gk_ptr, g_last_bits, g_cur_bits,
            state_even, state_odd,
            w_uv_lds, k_lds, next_valid_t);

        for (int chunk = 1; chunk <= nt - 2; ++chunk) {
            const int t_begin = chunk * BT;
            const int chunk_next_valid_t =
                chunk == nt - 2 ? last_valid_t : BT;
            run_chunk_gated_delta_rule_fwd_chunk_bv64_lds32<
                Kernel_traits, Params, true, true>(
                params, chunk, t_begin, BT, t_begin + BT - 1,
                v_begin, k_ptr, w_ptr, u_ptr, h_ptr, v_new_ptr, g_ptr,
                gk_ptr, g_last_bits, g_cur_bits, state_even, state_odd,
                w_uv_lds, k_lds,
                chunk_next_valid_t);
        }
    }

    if (nt > 0 && last_valid_t > 0) {
        const int last_idx = last_t_begin + last_valid_t - 1;
        if (last_valid_t == BT) {
            run_chunk_gated_delta_rule_fwd_chunk_bv64_lds32<
                Kernel_traits, Params, true, false>(
                params, last_chunk, last_t_begin, BT, last_idx, v_begin,
                k_ptr, w_ptr, u_ptr, h_ptr, v_new_ptr, g_ptr, gk_ptr,
                g_last_bits, g_cur_bits, state_even, state_odd,
                w_uv_lds, k_lds);
        } else {
            run_chunk_gated_delta_rule_fwd_chunk_bv64_lds32<
                Kernel_traits, Params, false, false>(
                params, last_chunk, last_t_begin, last_valid_t, last_idx,
                v_begin, k_ptr, w_ptr, u_ptr, h_ptr, v_new_ptr, g_ptr,
                gk_ptr, g_last_bits, g_cur_bits, state_even, state_odd,
                w_uv_lds, k_lds);
        }
    }

    if constexpr (Kernel_traits::Store_final_state) {
        wait_all_and_barrier();
        if (binfo.has_state()) {
            fla_store_final_state_bv64_vgpr<Kernel_traits, Params>(
                params, v_begin, ht_ptr, state_even, state_odd);
        }
    }
    wait_all_and_barrier();
}


// -----------------------------------------------------------------------------------------------
// gfx938 BV128: one contiguous V32 per wave, two adjacent V rows per lane.
// state_[vp][bk][i] owns H[32*wave+2*p+vp, 32*bk+8*q+2*i+{0,1}].
// GEMM0 LIT produces even/odd V4 projections whose union is contiguous V8;
// GEMM1 reads BOTH V alt halves and closes this mapping with LIT+LTS.
// W occupies LDS [0,16 KiB), then U/V reuse it through fla_uv_index_bv128.
// Each W half is released after its GEMM0 BK range; K stays in [16,32 KiB).
// -----------------------------------------------------------------------------------------------

template <int BkBegin, int BkEnd, typename Kernel_traits, typename Params>
__device__ __forceinline__ void fla_gemm0_bv128_lit_range(
    typename Kernel_traits::Element *w_lds,
    const fla_f32x4 (&state_even)[2][4],
    const fla_f32x4 (&state_odd)[2][4],
    fla_f32x4 (&projection)[2][4], const Params &params, const int chunk,
    const int v_begin, typename Kernel_traits::Element *h_ptr)
{
    using Element = typename Kernel_traits::Element;
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;
    using index_t = typename Kernel_traits::index_t;
    const int wave = threadIdx.x / 64;
    const int p = threadIdx.x & 15;
    const int q = (threadIdx.x & 63) >> 4;
#pragma unroll
    for (int bk = BkBegin; bk < BkEnd; ++bk) {
        ElementVec4 lo[2], hi[2];
#pragma unroll
        for (int vp = 0; vp < 2; ++vp) {
            lo[vp] = fla_make_gemm0_state_operand_bv64<0, Element>(
                state_even[vp][bk], state_odd[vp][bk]);
            hi[vp] = fla_make_gemm0_state_operand_bv64<1, Element>(
                state_even[vp][bk], state_odd[vp][bk]);
        }
#pragma unroll
        for (int ts = 0; ts < 4; ++ts) {
            const fla_u32x4 w_raw =
                fla_read_w_stage_bv64<Element, 64, 128, 4>(w_lds, ts, bk);
            const ElementVec4 w_lo = fla_vec4_from_pack<Element>(w_raw, 0);
            const ElementVec4 w_hi = fla_vec4_from_pack<Element>(w_raw, 4);
#pragma unroll
            for (int vp = 0; vp < 2; ++vp) {
                projection[vp][ts] = fla_mmac_f32_16x16x16_lit<Element>(
                    w_lo, lo[vp], projection[vp][ts]);
                projection[vp][ts] = fla_mmac_f32_16x16x16_lit<Element>(
                    w_hi, hi[vp], projection[vp][ts]);
            }
        }
#pragma unroll
        for (int vp = 0; vp < 2; ++vp) {
            const int v = v_begin + 32 * wave + 2 * p + vp;
            const fla_u32x2 a = ck_tile::bit_cast<fla_u32x2>(lo[vp]);
            const fla_u32x2 b = ck_tile::bit_cast<fla_u32x2>(hi[vp]);
            const int32_t offset = static_cast<int32_t>(
                (index_t(chunk) * params.h_chunk_stride +
                 index_t(v) * params.K + 32 * bk + 8 * q) * sizeof(Element));
            fla_buffer_store_vgpr<4>(
                h_ptr, offset, fla_u32x4{a[0], a[1], b[0], b[1]});
        }
        // Complete this BK contribution here. Otherwise LLVM can sink the
        // later-consumed T32 projections and retain several W/state packs
        // across the U/K publication points instead of reusing their VGPRs.
        asm volatile(""
            : "+v"(projection[0][0]), "+v"(projection[0][1]),
              "+v"(projection[0][2]), "+v"(projection[0][3]),
              "+v"(projection[1][0]), "+v"(projection[1][1]),
              "+v"(projection[1][2]), "+v"(projection[1][3]));
    }
}

__device__ __forceinline__ void fla_scale_state_gk_bv128(
    const fla_f32x2 pair, const int bk,
    fla_f32x4 (&state_even)[2][4], fla_f32x4 (&state_odd)[2][4])
{
    const int q = (threadIdx.x & 63) >> 4;
    // Gather each K8 factor once; both adjacent V rows use these factors.
    fla_f32x4 even, odd;
#pragma unroll
    for (int i = 0; i < 4; ++i) {
        const int source = (16 * bk + 4 * q + i) * sizeof(uint32_t);
        even[i] = ck_tile::bit_cast<float>(fla_ds_bpermute_u32(
            source, ck_tile::bit_cast<uint32_t>(pair[0])));
        odd[i] = ck_tile::bit_cast<float>(fla_ds_bpermute_u32(
            source, ck_tile::bit_cast<uint32_t>(pair[1])));
    }
#pragma unroll
    for (int vp = 0; vp < 2; ++vp) {
#pragma unroll
        for (int i = 0; i < 2; ++i) {
            const fla_f32x2 e = fla_pk_mul_f32(
                fla_f32x2{state_even[vp][bk][2*i], state_even[vp][bk][2*i+1]},
                fla_f32x2{even[2*i], even[2*i+1]});
            const fla_f32x2 o = fla_pk_mul_f32(
                fla_f32x2{state_odd[vp][bk][2*i], state_odd[vp][bk][2*i+1]},
                fla_f32x2{odd[2*i], odd[2*i+1]});
            state_even[vp][bk][2*i] = e[0];
            state_even[vp][bk][2*i+1] = e[1];
            state_odd[vp][bk][2*i] = o[0];
            state_odd[vp][bk][2*i+1] = o[1];
        }
    }
}

template <int TsBegin, int TsEnd, typename Kernel_traits, typename Params,
          bool FullChunk>
__device__ __forceinline__ void fla_residual_bv128_range(
    const Params &params, const int chunk, const int valid_t, const int v_begin,
    typename Kernel_traits::Element *v_new_ptr,
    typename Kernel_traits::Element *uv_lds,
    const fla_f32x4 (&projection)[2][4], const float (&row_scale)[4])
{
    using Element = typename Kernel_traits::Element;
    using index_t = typename Kernel_traits::index_t;
    const int p = threadIdx.x & 15;
    const int q = (threadIdx.x & 63) >> 4;
    const int wave = threadIdx.x / 64;
#pragma unroll
    for (int ts = TsBegin; ts < TsEnd; ++ts) {
        const int t = 16 * ts + p;
        const bool valid_row = FullChunk || t < valid_t;
        const fla_u32x4 u_raw = fla_read_u_bv128(uv_lds, ts);
        // Interleave V parity here; the persistent state uses K parity.
        fla_f32x4 even, odd;
        fla_unpack_state_bk8_bv64<Element>(u_raw, even, odd);
        even -= projection[0][ts];
        odd -= projection[1][ts];
        if (!valid_row) {
            even = fla_f32x4{0, 0, 0, 0};
            odd = fla_f32x4{0, 0, 0, 0};
        }
        if constexpr (Kernel_traits::Save_new_value) {
            const int v = v_begin + 32 * wave + 8 * q;
            const int32_t offset = static_cast<int32_t>(
                (index_t(64 * chunk + t) * params.v_new_row_stride + v) *
                sizeof(Element));
            // Save the residual before row gating.
            fla_buffer_store_vgpr<4>(
                v_new_ptr, valid_row ? offset : -1,
                fla_pack_state_bk8_bv64<Element>(even, odd));
        }
        if constexpr (Kernel_traits::Use_G) {
            if (valid_row) {
                fla_scale_v4_pairs(even, row_scale[ts]);
                fla_scale_v4_pairs(odd, row_scale[ts]);
            }
        }
        // Each lane replaces only its own U8; tail lanes publish zero.
        fla_store_v_bv128(uv_lds, ts,
                          fla_pack_state_bk8_bv64<Element>(even, odd));
    }
}

template <int TsBegin, typename Kernel_traits>
__device__ __forceinline__ void fla_gemm1_bv128_t32(
    typename Kernel_traits::Element *k_lds, const fla_u32x4 (&v_raw)[2],
    const float state_scale, const fla_f32x2 gk_scale,
    fla_f32x4 (&state_even)[2][4], fla_f32x4 (&state_odd)[2][4])
{
    using Element = typename Kernel_traits::Element;
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;
    static_assert(TsBegin == 0 || TsBegin == 2);
#pragma unroll
    for (int bk = 0; bk < 4; ++bk) {
        // Scale once, before the first T32 contribution. Each accumulator
        // retains the original ts=0,1,2,3 MMAC order across the two calls.
        if constexpr (TsBegin == 0) {
#pragma unroll
            for (int vp = 0; vp < 2; ++vp) {
                fla_scale_v4_pairs(state_even[vp][bk], state_scale);
                fla_scale_v4_pairs(state_odd[vp][bk], state_scale);
            }
            if constexpr (Kernel_traits::Use_GK) {
                fla_scale_state_gk_bv128(gk_scale, bk, state_even, state_odd);
            }
        }
#pragma unroll
        for (int ts = TsBegin; ts < TsBegin + 2; ++ts) {
            const fla_u32x4 k_raw =
                fla_read_k_stage_alt_bv64<Element, 64, 128, 4>(k_lds, bk, ts);
            const ElementVec4 ke = fla_vec4_from_pack<Element>(k_raw, 0);
            const ElementVec4 ko = fla_vec4_from_pack<Element>(k_raw, 4);
#pragma unroll
            for (int vp = 0; vp < 2; ++vp) {
                const ElementVec4 v =
                    fla_vec4_from_pack<Element>(v_raw[ts - TsBegin], 4 * vp);
                state_even[vp][bk] = fla_mmac_f32_16x16x16_lit_lts<Element>(
                    ke, v, state_even[vp][bk]);
                state_odd[vp][bk] = fla_mmac_f32_16x16x16_lit_lts<Element>(
                    ko, v, state_odd[vp][bk]);
            }
        }
    }
}

template <typename Kernel_traits, typename Params, bool FullChunk,
          bool PrefetchNextW>
__device__ __forceinline__ void
run_chunk_gated_delta_rule_fwd_chunk_bv128_lds32(
    const Params &params, const int chunk, const int valid_t,
    const int v_begin,
    const typename Kernel_traits::Element *k_ptr,
    const typename Kernel_traits::Element *w_ptr,
    const typename Kernel_traits::Element *u_ptr,
    typename Kernel_traits::Element *h_ptr,
    typename Kernel_traits::Element *v_new_ptr,
    const float *g_ptr, const float *gk_ptr,
    uint32_t &g_last_bits, uint32_t (&g_cur_bits)[4],
    fla_f32x4 (&state_even)[2][4], fla_f32x4 (&state_odd)[2][4],
    typename Kernel_traits::Element *w_uv_lds,
    typename Kernel_traits::Element *k_lds, const int next_valid_t = 64)
{
    using Element = typename Kernel_traits::Element;
    using index_t = typename Kernel_traits::index_t;
    constexpr bool Use_G = Kernel_traits::Use_G;
    constexpr bool Use_GK = Kernel_traits::Use_GK;
    constexpr bool Use_exp2 = Kernel_traits::Use_exp2;
    constexpr bool Use_safe_exp = Kernel_traits::Use_safe_exp;
    const int t_begin = 64 * chunk;
    const int last_idx = t_begin + valid_t - 1;
    static_assert(!PrefetchNextW || FullChunk);

    // W is carried from the prologue or the preceding chunk. G is younger
    // than both W halves and can remain in flight during GEMM0.
    // Native DS accesses/barriers let LLVM place the required LDS waits.
    // Inline-asm VMEM requests still need the explicit age counts below.
    wait_vmcnt<Use_G ? 4 : 0>();
    fla_lds_barrier();

    fla_f32x4 projection[2][4] = {};
    fla_gemm0_bv128_lit_range<0, 2, Kernel_traits>(
        w_uv_lds, state_even, state_odd, projection,
        params, chunk, v_begin, h_ptr);
    // Every wave must release low W before any U producer overwrites it.
    fla_lds_barrier();
    const Element *u_chunk =
        u_ptr + index_t(t_begin) * params.u_row_stride + v_begin;
    const Element *k_chunk =
        k_ptr + index_t(t_begin) * params.k_row_stride;
    // Preserve the first-use order: U_low, GK, K_low, U_high, K_high.
    // K halves are T32xK128; W halves are T64xK64.
    compiler_sched_barrier();
    fla_prefetch_u_bv128_to_lds<0, 2, Element, index_t, !FullChunk>(
        w_uv_lds, u_chunk, params.u_row_stride, valid_t);
    compiler_sched_barrier();
    fla_u32x2 gk_raw = {0, 0};
    if constexpr (Use_GK) {
        gk_raw = fla_prefetch_gk_pair_bv64<index_t>(
            gk_ptr, params.gk_row_stride, last_idx);
    }
    compiler_sched_barrier();
    fla_prefetch_k_to_lds<Element, 64, 128, 4, !FullChunk, 0, 2>(
        k_lds, k_chunk, params.k_row_stride, valid_t);
    compiler_sched_barrier();

    fla_gemm0_bv128_lit_range<2, 4, Kernel_traits>(
        w_uv_lds, state_even, state_odd, projection,
        params, chunk, v_begin, h_ptr);
    fla_lds_barrier();
    compiler_sched_barrier();
    fla_prefetch_u_bv128_to_lds<2, 4, Element, index_t, !FullChunk>(
        w_uv_lds, u_chunk, params.u_row_stride, valid_t);
    compiler_sched_barrier();
    fla_prefetch_k_to_lds<Element, 64, 128, 4, !FullChunk, 2, 4>(
        k_lds, k_chunk, params.k_row_stride, valid_t);
    compiler_sched_barrier();

    constexpr int kHighHStores = 4;
    constexpr int kHalfVStores = Kernel_traits::Save_new_value ? 2 : 0;
    constexpr int kHalfWNext = PrefetchNextW ? 2 : 0;
    // Younger than U_low: GK, K_low x2, h_high x4, U_high x2, K_high x2.
    wait_vmcnt<(Use_GK ? 1 : 0) + 2 + kHighHStores + 4>();
    fla_lds_barrier();

    float state_scale = 1.0f;
    float row_scale[4] = {1.0f, 1.0f, 1.0f, 1.0f};
    if constexpr (Use_G) {
        fla_broadcast_g_cur_bv64(g_cur_bits);
        g_last_bits = fla_recover_g_last_bits_bv64<FullChunk>(valid_t, g_cur_bits);
        const float g_last = ck_tile::bit_cast<float>(g_last_bits);
        state_scale = fla_exp<false, Use_exp2>(g_last);
#pragma unroll
        for (int ts = 0; ts < 4; ++ts) {
            row_scale[ts] = fla_exp<Use_safe_exp, Use_exp2>(
                g_last - ck_tile::bit_cast<float>(g_cur_bits[ts]));
        }
    }

    fla_residual_bv128_range<0, 2, Kernel_traits, Params, FullChunk>(
        params, chunk, valid_t, v_begin, v_new_ptr, w_uv_lds,
        projection, row_scale);
    fla_lds_barrier();
    fla_u32x4 v_low[2];
#pragma unroll
    for (int ts = 0; ts < 2; ++ts) {
        v_low[ts] = fla_read_v_alt_bv128(w_uv_lds, ts);
    }
    // Publish K_low/GK and finish every low-V read before W_next overwrites
    // the low 8 KiB. Younger: h_high, U_high, K_high, v_new_low.
    wait_vmcnt<kHighHStores + 4 + kHalfVStores>();
    fla_lds_barrier();
    if constexpr (PrefetchNextW) {
        fla_prefetch_w_to_lds<Element, 64, 128, 4, true, 0, 1>(
            w_uv_lds, w_ptr + index_t(t_begin + 64) * params.w_row_stride,
            params.w_row_stride, next_valid_t);
        compiler_sched_barrier();
    }

    fla_f32x2 gk_scale = {1.0f, 1.0f};
    if constexpr (Use_GK) {
        const fla_f32x2 pair = ck_tile::bit_cast<fla_f32x2>(gk_raw);
        gk_scale = fla_f32x2{fla_exp<false, Use_exp2>(pair[0]),
                             fla_exp<false, Use_exp2>(pair[1])};
    }
    fla_gemm1_bv128_t32<0, Kernel_traits>(
        k_lds, v_low, state_scale, gk_scale, state_even, state_odd);

    // U_high is older than K_high, v_new_low, and W_next_low.
    wait_vmcnt<2 + kHalfVStores + kHalfWNext>();
    fla_lds_barrier();
    fla_residual_bv128_range<2, 4, Kernel_traits, Params, FullChunk>(
        params, chunk, valid_t, v_begin, v_new_ptr, w_uv_lds,
        projection, row_scale);
    fla_lds_barrier();
    fla_u32x4 v_high[2];
#pragma unroll
    for (int ts = 0; ts < 2; ++ts) {
        v_high[ts] = fla_read_v_alt_bv128(w_uv_lds, ts + 2);
    }
    // Publish K_high and finish high-V reads. The two v_new store groups
    // and W_next_low are younger; the upper W/G prefetches follow this wait.
    wait_vmcnt<2 * kHalfVStores + kHalfWNext>();
    fla_lds_barrier();
    if constexpr (PrefetchNextW) {
        fla_prefetch_w_to_lds<Element, 64, 128, 4, true, 1, 2>(
            w_uv_lds, w_ptr + index_t(t_begin + 64) * params.w_row_stride,
            params.w_row_stride, next_valid_t);
        compiler_sched_barrier();
        if constexpr (Use_G) {
            fla_prefetch_g_chunk_bv64<index_t>(
                g_ptr, params.g_row_stride, t_begin + 64, next_valid_t,
                g_last_bits, g_cur_bits);
            compiler_sched_barrier();
        }
    }
    fla_gemm1_bv128_t32<2, Kernel_traits>(
        k_lds, v_high, state_scale, gk_scale, state_even, state_odd);
    // K can be reused next chunk. W_next/G_next remain governed by the
    // next entrance wait; terminal output stores are drained by the body.
    fla_lds_barrier();
}

template <typename Kernel_traits, typename Params>
__device__ void run_chunk_gated_delta_rule_fwd_kernel_body_bv128_lds32(
    const Params &params, const int i_v, const int i_nh)
{
    using Element = typename Kernel_traits::Element;
    using State = typename Kernel_traits::State;
    using index_t = typename Kernel_traits::index_t;
    static_assert(Kernel_traits::kBlockT == 64 &&
                  Kernel_traits::kBlockK == 128 &&
                  Kernel_traits::kBlockV == 128 &&
                  Kernel_traits::kNWarps == 4 &&
                  Kernel_traits::Transpose_state,
                  "BV128 requires BT64/BK128/W4 and transposed state");
    static_assert(Kernel_traits::w_smem_size == 16 * 1024 &&
                  Kernel_traits::k_smem_size == 16 * 1024 &&
                  Kernel_traits::smem_size == 32 * 1024,
                  "BV128 requires W/U/V16K + K16K");
    const int i_n = i_nh / params.H;
    const int i_h = i_nh - i_n * params.H;
    const int v_begin = i_v * 128;
    BlockInfo<Kernel_traits::Is_varlen, typename Kernel_traits::VarlenIndexT>
        binfo(params, i_n);
    const int nt = binfo.n_chunks();
    const int seqlen = binfo.actual_seqlen();
    const int h_per_k = params.H / params.Hg;
    const Element *k_ptr = reinterpret_cast<const Element *>(params.k_ptr) +
        binfo.template k_offset<index_t>(
            i_h, params.k_row_stride, params.k_head_stride, h_per_k);
    const Element *w_ptr = reinterpret_cast<const Element *>(params.w_ptr) +
        binfo.template w_offset<index_t>(
            i_h, params.w_row_stride, params.w_head_stride);
    const Element *u_ptr = reinterpret_cast<const Element *>(params.u_ptr) +
        binfo.template v_offset<index_t>(
            i_h, params.u_row_stride, params.u_head_stride);
    Element *h_ptr = reinterpret_cast<Element *>(params.h_ptr) +
        binfo.template h_offset<index_t>(
            i_h, params.h_chunk_stride, params.h_head_stride);
    Element *v_new_ptr = nullptr;
    if constexpr (Kernel_traits::Save_new_value) {
        v_new_ptr = reinterpret_cast<Element *>(params.v_new_ptr) +
            binfo.template v_offset<index_t>(
                i_h, params.v_new_row_stride, params.v_new_head_stride);
    }
    const float *g_ptr = nullptr, *gk_ptr = nullptr;
    if constexpr (Kernel_traits::Use_G) {
        g_ptr = reinterpret_cast<const float *>(params.g_ptr) +
            binfo.template g_offset<index_t>(i_h, params.g_row_stride);
    }
    if constexpr (Kernel_traits::Use_GK) {
        gk_ptr = reinterpret_cast<const float *>(params.gk_ptr) +
            binfo.template gk_offset<index_t>(
                i_h, params.gk_row_stride, params.gk_head_stride);
    }
    const State *h0_ptr = nullptr;
    State *ht_ptr = nullptr;
    if constexpr (Kernel_traits::Use_initial_state) {
        if (binfo.has_state()) {
            h0_ptr = reinterpret_cast<const State *>(params.h0_ptr) +
                binfo.template state_offset<index_t>(
                    i_h, params.h0_batch_stride, params.h0_head_stride);
        }
    }
    if constexpr (Kernel_traits::Store_final_state) {
        if (binfo.has_state()) {
            ht_ptr = reinterpret_cast<State *>(params.ht_ptr) +
                binfo.template state_offset<index_t>(
                    i_h, params.ht_batch_stride, params.ht_head_stride);
        }
    }

    extern __shared__ uint8_t lds_base[];
    Element *w_uv_lds = reinterpret_cast<Element *>(lds_base);
    Element *k_lds = reinterpret_cast<Element *>(lds_base + 16 * 1024);
    const int wave = threadIdx.x / 64;
    const int p = threadIdx.x & 15;
    const int q = (threadIdx.x & 63) >> 4;
    fla_f32x4 state_even[2][4] = {}, state_odd[2][4] = {};
    if constexpr (Kernel_traits::Use_initial_state) {
        if (binfo.has_state()) {
#pragma unroll
            for (int vp = 0; vp < 2; ++vp) {
#pragma unroll
                for (int bk = 0; bk < 4; ++bk) {
                    const int v = v_begin + 32 * wave + 2 * p + vp;
                    const index_t offset = index_t(v) * params.K + 32 * bk + 8 * q;
                    if constexpr (std::is_same_v<State, float>) {
                        const fla_u32x4 lo = fla_load_state_fp32x4_direct(h0_ptr + offset);
                        const fla_u32x4 hi = fla_load_state_fp32x4_direct(h0_ptr + offset + 4);
                        fla_unpack_state_bk8_bv64_fp32(
                            lo, hi, state_even[vp][bk], state_odd[vp][bk]);
                    } else {
                        const fla_u32x4 raw = fla_buffer_load_vgpr<4>(
                            h0_ptr, static_cast<int32_t>(offset * sizeof(State)));
                        wait_vmcnt<0>();
                        fla_unpack_state_bk8_bv64<State>(
                            raw, state_even[vp][bk], state_odd[vp][bk]);
                    }
                }
            }
        }
    }
    uint32_t g_last_bits = 0, g_cur_bits[4] = {};
    if (nt > 0) {
        const int first_valid_t = seqlen < 64 ? seqlen : 64;
        compiler_sched_barrier();
        fla_prefetch_w_to_lds<Element, 64, 128, 4, true>(
            w_uv_lds, w_ptr, params.w_row_stride, first_valid_t);
        compiler_sched_barrier();
        if constexpr (Kernel_traits::Use_G) {
            fla_prefetch_g_chunk_bv64<index_t>(
                g_ptr, params.g_row_stride, 0, first_valid_t,
                g_last_bits, g_cur_bits);
            compiler_sched_barrier();
        }
    }
    // Keep the partial terminal path outside the recurrent full-chunk loop.
    // Otherwise its lane addresses stay live across every full chunk.
    for (int chunk = 0; chunk < nt - 1; ++chunk) {
        const int remaining = seqlen - 64 * (chunk + 1);
        const int next_valid_t = remaining < 64 ? remaining : 64;
        run_chunk_gated_delta_rule_fwd_chunk_bv128_lds32<Kernel_traits, Params, true, true>(
            params, chunk, 64, v_begin, k_ptr, w_ptr, u_ptr, h_ptr,
            v_new_ptr, g_ptr, gk_ptr, g_last_bits, g_cur_bits,
            state_even, state_odd, w_uv_lds, k_lds, next_valid_t);
    }
    if (nt > 0) {
        const int chunk = nt - 1;
        const int valid_t = seqlen - 64 * chunk;
        if (valid_t == 64) {
            run_chunk_gated_delta_rule_fwd_chunk_bv128_lds32<Kernel_traits, Params, true, false>(
                params, chunk, 64, v_begin, k_ptr, w_ptr, u_ptr, h_ptr,
                v_new_ptr, g_ptr, gk_ptr, g_last_bits, g_cur_bits,
                state_even, state_odd, w_uv_lds, k_lds);
        } else {
            run_chunk_gated_delta_rule_fwd_chunk_bv128_lds32<Kernel_traits, Params, false, false>(
                params, chunk, valid_t, v_begin, k_ptr, w_ptr, u_ptr, h_ptr,
                v_new_ptr, g_ptr, gk_ptr, g_last_bits, g_cur_bits,
                state_even, state_odd, w_uv_lds, k_lds);
        }
    }
    if constexpr (Kernel_traits::Store_final_state) {
        if (binfo.has_state()) {
#pragma unroll
            for (int vp = 0; vp < 2; ++vp) {
#pragma unroll
                for (int bk = 0; bk < 4; ++bk) {
                    const int v = v_begin + 32 * wave + 2 * p + vp;
                    const index_t offset = index_t(v) * params.K + 32 * bk + 8 * q;
                    if constexpr (std::is_same_v<State, float>) {
                        const fla_f32x4 e = state_even[vp][bk], o = state_odd[vp][bk];
                        fla_store_state_fp32x4_direct(ht_ptr + offset,
                            ck_tile::bit_cast<fla_u32x4>(fla_f32x4{e[0], o[0], e[1], o[1]}));
                        fla_store_state_fp32x4_direct(ht_ptr + offset + 4,
                            ck_tile::bit_cast<fla_u32x4>(fla_f32x4{e[2], o[2], e[3], o[3]}));
                    } else {
                        fla_buffer_store_vgpr<4>(
                            ht_ptr, static_cast<int32_t>(offset * sizeof(State)),
                            fla_pack_state_bk8_bv64<State>(
                                state_even[vp][bk], state_odd[vp][bk]));
                    }
                }
            }
        }
    }
    wait_vmcnt<0>();
    fla_lds_barrier();
}

template <typename Kernel_traits, typename Params>
__device__ void
run_chunk_gated_delta_rule_fwd_kernel_body_bv32(
    const Params &params, const int i_v, const int i_nh)
{
    using Element = typename Kernel_traits::Element;
    using State = typename Kernel_traits::State;
    using index_t = typename Kernel_traits::index_t;

    constexpr int BK = Kernel_traits::kBlockK;
    constexpr int BV = Kernel_traits::kBlockV;
    constexpr int BT = Kernel_traits::kBlockT;
    constexpr int H_LOW_STRIDE = Kernel_traits::kHLowStride;

    constexpr bool Use_initial_state = Kernel_traits::Use_initial_state;
    constexpr bool Store_final_state = Kernel_traits::Store_final_state;
    constexpr bool Save_new_value    = Kernel_traits::Save_new_value;
    constexpr bool Use_G             = Kernel_traits::Use_G;
    constexpr bool Use_GK            = Kernel_traits::Use_GK;
    constexpr bool Is_varlen         = Kernel_traits::Is_varlen;

    static_assert(BK == 128, "Only K=128 is implemented");
    static_assert(BV == 32, "BV32 kernel body requires kBlockV=32");
    static_assert(BT == 64, "Only BT=64 is implemented");
    (void)Save_new_value;
    (void)Use_G;
    (void)Use_GK;

    const int tid = threadIdx.x;
    const int i_n = i_nh / params.H;
    const int i_h = i_nh - i_n * params.H;
    const int v_begin = i_v * BV;

    BlockInfo<Is_varlen, typename Kernel_traits::VarlenIndexT> binfo(params, i_n);
    const int nt = binfo.n_chunks();
    const int seqlen = binfo.actual_seqlen();
    const int h_per_k = params.H / params.Hg;

    const Element *__restrict__ k_ptr =
        reinterpret_cast<const Element *>(params.k_ptr) +
        binfo.template k_offset<index_t>(i_h, params.k_row_stride,
                                         params.k_head_stride, h_per_k);
    const Element *__restrict__ w_ptr =
        reinterpret_cast<const Element *>(params.w_ptr) +
        binfo.template w_offset<index_t>(i_h, params.w_row_stride,
                                         params.w_head_stride);
    const Element *__restrict__ u_ptr =
        reinterpret_cast<const Element *>(params.u_ptr) +
        binfo.template v_offset<index_t>(i_h, params.u_row_stride,
                                         params.u_head_stride);
    Element *__restrict__ h_ptr =
        reinterpret_cast<Element *>(params.h_ptr) +
        binfo.template h_offset<index_t>(i_h, params.h_chunk_stride,
                                         params.h_head_stride);

    Element *__restrict__ v_new_ptr = nullptr;
    if constexpr (Save_new_value) {
        v_new_ptr = reinterpret_cast<Element *>(params.v_new_ptr) +
                    binfo.template v_offset<index_t>(i_h, params.v_new_row_stride,
                                                     params.v_new_head_stride);
    }

    const float *__restrict__ g_ptr = nullptr;
    if constexpr (Use_G) {
        g_ptr = reinterpret_cast<const float *>(params.g_ptr) +
                binfo.template g_offset<index_t>(i_h, params.g_row_stride);
    }

    const float *__restrict__ gk_ptr = nullptr;
    if constexpr (Use_GK) {
        gk_ptr = reinterpret_cast<const float *>(params.gk_ptr) +
                 binfo.template gk_offset<index_t>(i_h, params.gk_row_stride,
                                                   params.gk_head_stride);
    }

    const State *__restrict__ h0_ptr = nullptr;
    if constexpr (Use_initial_state) {
        if (binfo.has_state()) {
            h0_ptr = reinterpret_cast<const State *>(params.h0_ptr) +
                     binfo.template state_offset<index_t>(
                         i_h, params.h0_batch_stride, params.h0_head_stride);
        }
    }

    State *__restrict__ ht_ptr = nullptr;
    if constexpr (Store_final_state) {
        if (binfo.has_state()) {
            ht_ptr = reinterpret_cast<State *>(params.ht_ptr) +
                     binfo.template state_offset<index_t>(
                         i_h, params.ht_batch_stride, params.ht_head_stride);
        }
    }

    extern __shared__ uint8_t lds_base[];
    constexpr int V_TILE_BYTES = Kernel_traits::v_tile_smem_size;
    constexpr int H_LOW_BYTES = Kernel_traits::h_low_smem_size;
    constexpr int K_TILE_BYTES = Kernel_traits::k_smem_size;
    constexpr int V_TILE_OFFSET = 0;
    constexpr int H_LOW_OFFSET = V_TILE_OFFSET + V_TILE_BYTES;
    constexpr int K_TILE_OFFSET = H_LOW_OFFSET + H_LOW_BYTES;
    static_assert(K_TILE_OFFSET + K_TILE_BYTES == Kernel_traits::smem_size,
                  "BV32 manual LDS layout must match trait smem_size");

    Element *v_tile = reinterpret_cast<Element *>(lds_base + V_TILE_OFFSET);
    Element *h_low_tile = reinterpret_cast<Element *>(lds_base + H_LOW_OFFSET);
    Element *k_lds_tile =
        reinterpret_cast<Element *>(lds_base + K_TILE_OFFSET);

    const int warp_id = tid / 64;
    const int lane_id = tid & 63;
    const int lane_m = lane_id & 15;
    const int lane_g = lane_id >> 4;
    const int t_local = warp_id * 16 + lane_m;
    const int k0 = warp_id * 32 + lane_m * 2;

    fla_f32x2 state_reg[8];
#pragma unroll
    for (int s = 0; s < 8; ++s) {
        const int v_local =
            fla_bv32_v_local_from_state_slot(lane_g, s);
        const int v_col = v_begin + v_local;
        fla_f32x2 value = {0.0f, 0.0f};
        if constexpr (Use_initial_state) {
            if (binfo.has_state() && v_col < params.V) {
                value = load_state_pair(
                    h0_ptr + index_t(v_col) * params.K + k0);
            }
        }
        state_reg[s] = value;
    }

    fla_store_h_low_state_reg_swizzled_bv32<Element>(
        h_low_tile, lane_g, k0, state_reg);
    wait_lgkmcnt0_barrier();

    fla_u32x4 w_carried[4] = {};
    const index_t w_tensor_elems =
        index_t(params.T) * params.H * params.K;

    const int last_chunk = nt - 1;
    const int last_t_begin = last_chunk * BT;
    const int last_valid_t = seqlen - last_t_begin;

    // Match the BV16 outer schedule: prologue carries W0, full chunks
    // prefetch W_next (with t-only OOB via voffset=-1), and the last chunk
    // consumes carried W instead of staging it locally.  This lets a full last
    // chunk use the full fast path and keeps the penultimate chunk in the
    // same steady-loop structure as BV16.
    if (nt > 0) {
        const int chunk0_valid_t = (nt >= 2) ? BT : last_valid_t;
        const bool chunk0_valid_row = t_local < chunk0_valid_t;
        fla_load_w_tile_bv32_vgpr<Element, index_t, BK>(
            w_ptr, index_t(0), params.w_row_stride, chunk0_valid_row,
            w_tensor_elems, w_carried);
        wait_vmcnt<0>();

        if (nt >= 2) {
            const int chunk0_next_valid_t = (nt == 2) ? last_valid_t : BT;
            run_chunk_gated_delta_rule_fwd_chunk_bv32_mmac<
                Kernel_traits, Params, true, true, true>(
                params, 0, 0, BT, BT - 1, v_begin, k_ptr, w_ptr, u_ptr,
                h_ptr, v_new_ptr, g_ptr, gk_ptr, state_reg, w_carried,
                v_tile, h_low_tile, nullptr, k_lds_tile, chunk0_next_valid_t);

            for (int chunk = 1; chunk <= nt - 2; ++chunk) {
                const int t_begin = chunk * BT;
                const int last_idx = t_begin + BT - 1;
                const int next_valid_t = (chunk == nt - 2) ? last_valid_t : BT;
                run_chunk_gated_delta_rule_fwd_chunk_bv32_mmac<
                    Kernel_traits, Params, true, true, true>(
                    params, chunk, t_begin, BT, last_idx, v_begin, k_ptr,
                    w_ptr, u_ptr, h_ptr, v_new_ptr, g_ptr, gk_ptr,
                    state_reg, w_carried, v_tile, h_low_tile, nullptr,
                    k_lds_tile, next_valid_t);
            }
        }

        if (last_valid_t > 0) {
            const int last_idx = last_t_begin + last_valid_t - 1;
            if (last_valid_t == BT) {
                run_chunk_gated_delta_rule_fwd_chunk_bv32_mmac<
                    Kernel_traits, Params, true, true, false>(
                    params, last_chunk, last_t_begin, BT, last_idx, v_begin,
                    k_ptr, w_ptr, u_ptr, h_ptr, v_new_ptr, g_ptr, gk_ptr,
                    state_reg, w_carried, v_tile, h_low_tile, nullptr,
                    k_lds_tile);
            } else {
                run_chunk_gated_delta_rule_fwd_chunk_bv32_mmac<
                    Kernel_traits, Params, false, true, false>(
                    params, last_chunk, last_t_begin, last_valid_t, last_idx,
                    v_begin, k_ptr, w_ptr, u_ptr, h_ptr, v_new_ptr, g_ptr,
                    gk_ptr, state_reg, w_carried, v_tile, h_low_tile, nullptr,
                    k_lds_tile);
            }
        }
    }

    if constexpr (Store_final_state) {
        wait_all_and_barrier();
        if (binfo.has_state()) {
            store_final_state_bv32<Kernel_traits, Params>(
                params, v_begin, ht_ptr, state_reg);
        }
        wait_all_and_barrier();
    }
}

template <typename Kernel_traits, typename Params>
__device__ void
run_chunk_gated_delta_rule_fwd_kernel_body_bv16(
    const Params &params, const int i_v, const int i_nh)
{
    using Element = typename Kernel_traits::Element;
    using State = typename Kernel_traits::State;
    using index_t = typename Kernel_traits::index_t;

    constexpr int BK = Kernel_traits::kBlockK;
    constexpr int BV = Kernel_traits::kBlockV;
    constexpr int BT = Kernel_traits::kBlockT;
    constexpr int H_LOW_STRIDE = Kernel_traits::kHLowStride;

    constexpr bool Use_initial_state = Kernel_traits::Use_initial_state;
    constexpr bool Store_final_state = Kernel_traits::Store_final_state;
    constexpr bool Save_new_value    = Kernel_traits::Save_new_value;
    constexpr bool Use_G             = Kernel_traits::Use_G;
    constexpr bool Use_GK            = Kernel_traits::Use_GK;
    constexpr bool Is_varlen         = Kernel_traits::Is_varlen;

    static_assert(BK == 128, "Only K=128 is implemented");
    static_assert(BV == 16,
                  "chunk_gated_delta_rule_fwd currently supports BV16 only");
    static_assert(BT == 64, "Only BT=64 is implemented");
    (void)Save_new_value;
    (void)Use_G;
    (void)Use_GK;

    const int tid = threadIdx.x;
    const int i_n = i_nh / params.H;
    const int i_h = i_nh - i_n * params.H;
    const int v_begin = i_v * BV;

    BlockInfo<Is_varlen, typename Kernel_traits::VarlenIndexT> binfo(params, i_n);
    const int nt = binfo.n_chunks();
    const int seqlen = binfo.actual_seqlen();
    const int h_per_k = params.H / params.Hg;

    const Element *__restrict__ k_ptr =
        reinterpret_cast<const Element *>(params.k_ptr) +
        binfo.template k_offset<index_t>(i_h, params.k_row_stride,
                                         params.k_head_stride, h_per_k);
    const Element *__restrict__ w_ptr =
        reinterpret_cast<const Element *>(params.w_ptr) +
        binfo.template w_offset<index_t>(i_h, params.w_row_stride,
                                         params.w_head_stride);
    const Element *__restrict__ u_ptr =
        reinterpret_cast<const Element *>(params.u_ptr) +
        binfo.template v_offset<index_t>(i_h, params.u_row_stride,
                                         params.u_head_stride);
    Element *__restrict__ h_ptr =
        reinterpret_cast<Element *>(params.h_ptr) +
        binfo.template h_offset<index_t>(i_h, params.h_chunk_stride,
                                         params.h_head_stride);

    Element *__restrict__ v_new_ptr = nullptr;
    if constexpr (Save_new_value) {
        v_new_ptr = reinterpret_cast<Element *>(params.v_new_ptr) +
                    binfo.template v_offset<index_t>(i_h, params.v_new_row_stride,
                                                     params.v_new_head_stride);
    }

    const float *__restrict__ g_ptr = nullptr;
    if constexpr (Use_G) {
        g_ptr = reinterpret_cast<const float *>(params.g_ptr) +
                binfo.template g_offset<index_t>(i_h, params.g_row_stride);
    }

    const float *__restrict__ gk_ptr = nullptr;
    if constexpr (Use_GK) {
        gk_ptr = reinterpret_cast<const float *>(params.gk_ptr) +
                 binfo.template gk_offset<index_t>(i_h, params.gk_row_stride,
                                                   params.gk_head_stride);
    }

    const State *__restrict__ h0_ptr = nullptr;
    if constexpr (Use_initial_state) {
        if (binfo.has_state()) {
            h0_ptr = reinterpret_cast<const State *>(params.h0_ptr) +
                     binfo.template state_offset<index_t>(
                         i_h, params.h0_batch_stride, params.h0_head_stride);
        }
    }

    State *__restrict__ ht_ptr = nullptr;
    if constexpr (Store_final_state) {
        if (binfo.has_state()) {
            ht_ptr = reinterpret_cast<State *>(params.ht_ptr) +
                     binfo.template state_offset<index_t>(
                         i_h, params.ht_batch_stride, params.ht_head_stride);
        }
    }

    extern __shared__ uint8_t lds_base[];
    constexpr int V_TILE_BYTES = Kernel_traits::v_tile_smem_size;
    constexpr int H_LOW_BYTES = Kernel_traits::h_low_smem_size;
    constexpr int W_TILE_BYTES = Kernel_traits::w_smem_size;
    constexpr int K_TILE_BYTES = Kernel_traits::k_smem_size;
    constexpr int V_TILE_OFFSET = 0;
    constexpr int H_LOW_OFFSET = V_TILE_OFFSET + V_TILE_BYTES;
    constexpr int W_TILE_OFFSET = H_LOW_OFFSET + H_LOW_BYTES;
    constexpr int K_TILE_OFFSET = W_TILE_OFFSET + W_TILE_BYTES;
    static_assert(K_TILE_OFFSET + K_TILE_BYTES == Kernel_traits::smem_size,
                  "manual LDS layout must match trait smem_size");

    Element *v_tile = reinterpret_cast<Element *>(lds_base + V_TILE_OFFSET);
    Element *h_low_tile = reinterpret_cast<Element *>(lds_base + H_LOW_OFFSET);
    Element *w_lds_tile =
        reinterpret_cast<Element *>(lds_base + W_TILE_OFFSET);
    Element *k_lds_tile =
        reinterpret_cast<Element *>(lds_base + K_TILE_OFFSET);

    const int warp_id = tid / 64;
    const int lane_id = tid & 63;
    const int lane_m = lane_id & 15;
    const int lane_k_group = lane_id >> 4;
    const int k0 = warp_id * 32 + lane_m * 2;

    fla_f32x2 state_reg[4];
#pragma unroll
    for (int s = 0; s < 4; ++s) {
        const int v_local = lane_k_group + s * 4;
        const int v_col = v_begin + v_local;
        fla_f32x2 value = {0.0f, 0.0f};
        if constexpr (Use_initial_state) {
            if (binfo.has_state() && v_col < params.V) {
                value = load_state_pair(
                    h0_ptr + index_t(v_col) * params.K + k0);
            }
        }
        state_reg[s] = value;
        fla_store_h_low_pair_kmajor<Element, H_LOW_STRIDE>(
            h_low_tile, v_local, k0, value);
    }
    wait_lgkmcnt0_barrier();

    constexpr int kCarriedWYoungerVmem = Save_new_value ? 1 : 0;

    const int last_chunk = nt - 1;
    const int last_t_begin = last_chunk * BT;
    const int last_valid_t = seqlen - last_t_begin;

    // Outer pipeline. Two orthogonal axes drive the specialization:
    //   (A) OOB / tail: only the last chunk may be a tail, and only the W
    //       prefetch whose target IS the last chunk needs bounds checking.
    //       We always prefetch with CheckBounds=true and drive the mask via
    //       the runtime next_valid_t argument (== BT disables the mask), so
    //       checked vs unchecked no longer needs separate code paths.
    //   (B) vmem age: the carried W of chunk 0 comes from the prologue (no
    //       v_new store is queued behind it, WPrefetchYoungerVmem = 0), while
    //       every later chunk's carried W comes from the previous chunk's
    //       epilogue (a v_new store follows it, WPrefetchYoungerVmem =
    //       kCarriedWYoungerVmem). This is a compile-time distinction, so
    //       chunk 0 must be peeled out of the steady loop.
    // The last chunk is also specialized for the FullChunk tail masks
    // (U / row-G / residual / K) and for EndBarrier.
    if (nt > 0) {
        const int chunk0_valid_t = (nt >= 2) ? BT : last_valid_t;
        fla_prefetch_w_to_lds<Element, BT, BK, Kernel_traits::kNWarps, true>(
            w_lds_tile, w_ptr, params.w_row_stride, chunk0_valid_t);

        if (nt >= 2) {
            const int chunk0_next_valid_t = (nt == 2) ? last_valid_t : BT;
            run_chunk_gated_delta_rule_fwd_chunk_bv16<
                Kernel_traits, Params, true, true, true, true, 0, false>(
                params, 0, 0, BT, BT - 1, v_begin, k_ptr, w_ptr, u_ptr, h_ptr,
                v_new_ptr, g_ptr, gk_ptr, state_reg, v_tile, h_low_tile,
                w_lds_tile, k_lds_tile, chunk0_next_valid_t);

            for (int chunk = 1; chunk <= nt - 2; ++chunk) {
                const int t_begin = chunk * BT;
                const int last_idx = t_begin + BT - 1;
                const int next_valid_t = (chunk == nt - 2) ? last_valid_t : BT;
                run_chunk_gated_delta_rule_fwd_chunk_bv16<
                    Kernel_traits, Params, true, true, true, true,
                    kCarriedWYoungerVmem, false>(
                    params, chunk, t_begin, BT, last_idx, v_begin, k_ptr, w_ptr,
                    u_ptr, h_ptr, v_new_ptr, g_ptr, gk_ptr, state_reg, v_tile,
                    h_low_tile, w_lds_tile, k_lds_tile, next_valid_t);
            }
        }

        if (last_valid_t > 0) {
            const int last_idx = last_t_begin + last_valid_t - 1;
            if (last_valid_t == BT) {
                if (nt >= 2) {
                    run_chunk_gated_delta_rule_fwd_chunk_bv16<
                        Kernel_traits, Params, true, true, false, false,
                        kCarriedWYoungerVmem, true>(
                        params, last_chunk, last_t_begin, BT, last_idx, v_begin,
                        k_ptr, w_ptr, u_ptr, h_ptr, v_new_ptr, g_ptr, gk_ptr,
                        state_reg, v_tile, h_low_tile, w_lds_tile, k_lds_tile,
                        BT);
                } else {
                    run_chunk_gated_delta_rule_fwd_chunk_bv16<
                        Kernel_traits, Params, true, true, false, false, 0,
                        true>(
                        params, last_chunk, last_t_begin, BT, last_idx, v_begin,
                        k_ptr, w_ptr, u_ptr, h_ptr, v_new_ptr, g_ptr, gk_ptr,
                        state_reg, v_tile, h_low_tile, w_lds_tile, k_lds_tile,
                        BT);
                }
            } else {
                if (nt >= 2) {
                    run_chunk_gated_delta_rule_fwd_chunk_bv16<
                        Kernel_traits, Params, false, true, false, false,
                        kCarriedWYoungerVmem, true>(
                        params, last_chunk, last_t_begin, last_valid_t,
                        last_idx, v_begin, k_ptr, w_ptr, u_ptr, h_ptr,
                        v_new_ptr, g_ptr, gk_ptr, state_reg, v_tile,
                        h_low_tile, w_lds_tile, k_lds_tile, BT);
                } else {
                    run_chunk_gated_delta_rule_fwd_chunk_bv16<
                        Kernel_traits, Params, false, true, false, false, 0,
                        true>(
                        params, last_chunk, last_t_begin, last_valid_t,
                        last_idx, v_begin, k_ptr, w_ptr, u_ptr, h_ptr,
                        v_new_ptr, g_ptr, gk_ptr, state_reg, v_tile,
                        h_low_tile, w_lds_tile, k_lds_tile, BT);
                }
            }
        }
    }

    if constexpr (Store_final_state) {
        wait_all_and_barrier();
        if (binfo.has_state()) {
            store_final_state_bv16<Kernel_traits, Params>(
                params, v_begin, ht_ptr, state_reg);
        }
        wait_all_and_barrier();
    }
}

template <typename Kernel_traits, typename Params>
__device__ void
run_chunk_gated_delta_rule_fwd_kernel_body(const Params &params, const int i_v,
                                           const int i_nh)
{
    if constexpr (Kernel_traits::kBlockV == 128) {
        run_chunk_gated_delta_rule_fwd_kernel_body_bv128_lds32<
            Kernel_traits, Params>(params, i_v, i_nh);
    } else if constexpr (Kernel_traits::kBlockV == 64) {
        run_chunk_gated_delta_rule_fwd_kernel_body_bv64_lds32<
            Kernel_traits, Params>(params, i_v, i_nh);
    } else if constexpr (Kernel_traits::kBlockV == 32) {
        run_chunk_gated_delta_rule_fwd_kernel_body_bv32<Kernel_traits, Params>(
            params, i_v, i_nh);
    } else {
        run_chunk_gated_delta_rule_fwd_kernel_body_bv16<Kernel_traits, Params>(
            params, i_v, i_nh);
    }
}

template <typename Kernel_traits, typename Params>
__global__ __launch_bounds__(Kernel_traits::kThreads,
                             Kernel_traits::kMinBlocksPerCU)
void chunk_gated_delta_rule_fwd_kernel(const Params params)
{
    const int i_v = blockIdx.x;
    const int i_nh = blockIdx.y;
    run_chunk_gated_delta_rule_fwd_kernel_body<Kernel_traits>(params, i_v, i_nh);
}

}  // namespace FLA_NAMESPACE
