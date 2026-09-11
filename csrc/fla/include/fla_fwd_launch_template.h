// SPDX-License-Identifier: MIT
#pragma once

#include "fla.h"
#include "static_switch.h"
#include "kernel_traits.h"
#include "fla_fwd_kernel.h"

namespace FLA_NAMESPACE {

////////////////////////////////////////////////////////////////////////////////////////////////////
// run_chunk_gated_delta_rule_fwd_impl
//
// Bottom of the dispatch tower: once every flag has been resolved into a
// compile-time constant, build the traits, compute grid/block, and launch.
////////////////////////////////////////////////////////////////////////////////////////////////////
template <
    int  kHeadDimK_,
    int  kHeadDimV_,
    int  kBlockT_,
    int  kBlockK_,
    int  kBlockV_,
    int  kNWarps_,
    bool Use_G_,
    bool Use_GK_,
    bool Use_initial_state_,
    bool Store_final_state_,
    bool Save_new_value_,
    ExpMode Exp_mode_,
    bool Transpose_state_,
    bool Is_varlen_,
    typename VarlenIndexT_ = int32_t,
    typename elem_type = ck_tile::fp16_t,
    typename state_type = float,
    typename accm_type = ck_tile::fp32_t>
void run_chunk_gated_delta_rule_fwd_impl(Delta_rule_params &params, hipStream_t stream)
{
    using Kernel_traits = chunk_gated_delta_rule_fwd_traits<
        kHeadDimK_, kHeadDimV_,
        kBlockT_, kBlockK_, kBlockV_,
        kNWarps_,
        Use_G_, Use_GK_,
        Use_initial_state_,
        Store_final_state_, Save_new_value_,
        Exp_mode_, Transpose_state_, Is_varlen_,
        VarlenIndexT_, elem_type, state_type, accm_type>;

    constexpr int    kBlockV   = Kernel_traits::kBlockV;
    constexpr int    kThreads  = Kernel_traits::kThreads;
    constexpr size_t smem_size = Kernel_traits::smem_size;

    const int grid_x = (params.V + kBlockV - 1) / kBlockV;
    const int grid_y = params.N * params.H;

    dim3 grid(grid_x, grid_y, 1);
    dim3 block(kThreads, 1, 1);

    hipLaunchKernelGGL(
        (chunk_gated_delta_rule_fwd_kernel<Kernel_traits, Delta_rule_params>),
        grid, block, smem_size, stream, params);
}

////////////////////////////////////////////////////////////////////////////////////////////////////
// Resolve the exponent policy after the gate flags are compile-time constants.
// With no G/GK input there is no exponent work, so canonicalize all frontend
// policies to Natural and emit just one kernel for that gate combination.
////////////////////////////////////////////////////////////////////////////////////////////////////
template <
    typename T,
    typename StateT,
    int kBlockV,
    bool Use_G,
    bool Use_GK,
    bool Use_initial_state,
    bool Store_final_state,
    bool Save_new_value,
    bool Transpose_state,
    bool Is_varlen,
    typename VarlenIndexT>
void dispatch_chunk_gated_delta_rule_fwd_exp_mode(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode)
{
    constexpr static int HeadDimK = 128;
    constexpr static int HeadDimV = 128;
    constexpr static int kBlockT = 64;
    constexpr static int kBlockK = 128;
    constexpr static int kNWarps = 4;

    if constexpr (!Use_G && !Use_GK) {
        run_chunk_gated_delta_rule_fwd_impl<
            HeadDimK, HeadDimV, kBlockT, kBlockK, kBlockV, kNWarps,
            Use_G, Use_GK, Use_initial_state, Store_final_state,
            Save_new_value, ExpMode::Natural, Transpose_state, Is_varlen,
            VarlenIndexT, T, StateT>(params, stream);
    } else {
        switch (exp_mode) {
        case ExpMode::Natural:
            run_chunk_gated_delta_rule_fwd_impl<
                HeadDimK, HeadDimV, kBlockT, kBlockK, kBlockV, kNWarps,
                Use_G, Use_GK, Use_initial_state, Store_final_state,
                Save_new_value, ExpMode::Natural, Transpose_state, Is_varlen,
                VarlenIndexT, T, StateT>(params, stream);
            break;
        case ExpMode::Exp2:
            run_chunk_gated_delta_rule_fwd_impl<
                HeadDimK, HeadDimV, kBlockT, kBlockK, kBlockV, kNWarps,
                Use_G, Use_GK, Use_initial_state, Store_final_state,
                Save_new_value, ExpMode::Exp2, Transpose_state, Is_varlen,
                VarlenIndexT, T, StateT>(params, stream);
            break;
        case ExpMode::SafeNatural:
            run_chunk_gated_delta_rule_fwd_impl<
                HeadDimK, HeadDimV, kBlockT, kBlockK, kBlockV, kNWarps,
                Use_G, Use_GK, Use_initial_state, Store_final_state,
                Save_new_value, ExpMode::SafeNatural, Transpose_state, Is_varlen,
                VarlenIndexT, T, StateT>(params, stream);
            break;
        default:
            TORCH_CHECK(false, "chunk_gated_delta_rule_fwd: invalid exponent policy");
        }
    }
}

////////////////////////////////////////////////////////////////////////////////////////////////////
// Per-(input dtype, state dtype, BV) dispatcher used by one flat instance TU. State-index
// selection remains runtime-only in BlockInfo and therefore is deliberately
// absent from this template tree.
////////////////////////////////////////////////////////////////////////////////////////////////////
template <typename T, typename StateT, int kBlockV>
void run_chunk_gated_delta_rule_fwd_k128_v128_bv(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode)
{
    static_assert(kBlockV == 16 || kBlockV == 32 || kBlockV == 128,
                  "generic chunk_gated_delta_rule_fwd dispatch supports BV16/BV32/BV128");

    BOOL_SWITCH(params.use_g, Use_G_, [&] {
    BOOL_SWITCH(params.use_gk, Use_GK_, [&] {
    BOOL_SWITCH(params.use_initial_state, Use_initial_state_, [&] {
    BOOL_SWITCH(params.store_final_state, Store_final_state_, [&] {
    BOOL_SWITCH(params.save_new_value, Save_new_value_, [&] {
    FIXED_TRUE_SWITCH(params.transpose_state_layout, Transpose_state_,
        "chunk_gated_delta_rule_fwd: only transpose_state_layout=true is currently implemented", [&] {
    BOOL_SWITCH(params.is_varlen, Is_varlen_, [&] {
        // Non-varlen does not touch cu_seqlens; pin IndexT=int32 so we do not
        // double that half of the dispatch tree. (chunk_offsets is always int64.)
        if constexpr (!Is_varlen_) {
            dispatch_chunk_gated_delta_rule_fwd_exp_mode<
                T, StateT, kBlockV, Use_G_, Use_GK_, Use_initial_state_,
                Store_final_state_, Save_new_value_, Transpose_state_,
                Is_varlen_, int32_t>(params, stream, exp_mode);
        } else {
            INDEX_SWITCH(params.index_is_int64, IndexT, [&] {
                dispatch_chunk_gated_delta_rule_fwd_exp_mode<
                    T, StateT, kBlockV, Use_G_, Use_GK_, Use_initial_state_,
                    Store_final_state_, Save_new_value_, Transpose_state_,
                    Is_varlen_, IndexT>(params, stream, exp_mode);
            });
        }
    });});});});});});});
}

// BV64 shares the public API and compile-time flag axes with BV16/BV32.  The
// host dispatcher decides whether the gfx938 implementation is appropriate;
// this layer materializes the selected gate/state/output/index combination.
template <typename T, typename StateT>
void run_chunk_gated_delta_rule_fwd_k128_v128_bv64(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode)
{
    BOOL_SWITCH(params.use_g, Use_G_, [&] {
    BOOL_SWITCH(params.use_gk, Use_GK_, [&] {
    BOOL_SWITCH(params.use_initial_state, Use_initial_state_, [&] {
    BOOL_SWITCH(params.store_final_state, Store_final_state_, [&] {
    BOOL_SWITCH(params.save_new_value, Save_new_value_, [&] {
    FIXED_TRUE_SWITCH(params.transpose_state_layout, Transpose_state_,
        "chunk_gated_delta_rule_fwd: BV64 requires transpose_state_layout=true", [&] {
    BOOL_SWITCH(params.is_varlen, Is_varlen_, [&] {
        if constexpr (!Is_varlen_) {
            dispatch_chunk_gated_delta_rule_fwd_exp_mode<
                T, StateT, 64, Use_G_, Use_GK_, Use_initial_state_,
                Store_final_state_, Save_new_value_, Transpose_state_,
                Is_varlen_, int32_t>(params, stream, exp_mode);
        } else {
            INDEX_SWITCH(params.index_is_int64, IndexT, [&] {
                dispatch_chunk_gated_delta_rule_fwd_exp_mode<
                    T, StateT, 64, Use_G_, Use_GK_, Use_initial_state_,
                    Store_final_state_, Save_new_value_, Transpose_state_,
                    Is_varlen_, IndexT>(params, stream, exp_mode);
            });
        }
    });});});});});});});
}

}  // namespace FLA_NAMESPACE
