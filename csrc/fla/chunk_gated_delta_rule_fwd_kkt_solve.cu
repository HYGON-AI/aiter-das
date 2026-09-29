// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
//
// Host entry for the standalone chunk_gated_delta_rule KKT solve.  The device
// kernel template lives in csrc/fla/include/ and dtype instances live in
// csrc/fla/instances/, matching the other FLA HIP operators.

#include "fla.h"

#include <ATen/hip/HIPContext.h>
#include <c10/hip/HIPException.h>
#include <torch/extension.h>

#include <cstdint>
#include <limits>
#include <optional>

#ifndef AITER_HIP_KERNEL_LAUNCH_CHECK
#if defined(C10_CUDA_KERNEL_LAUNCH_CHECK)
#define AITER_HIP_KERNEL_LAUNCH_CHECK() C10_CUDA_KERNEL_LAUNCH_CHECK()
#elif defined(C10_HIP_KERNEL_LAUNCH_CHECK)
#define AITER_HIP_KERNEL_LAUNCH_CHECK() C10_HIP_KERNEL_LAUNCH_CHECK()
#else
#define AITER_HIP_KERNEL_LAUNCH_CHECK() C10_HIP_CHECK(hipGetLastError())
#endif
#endif

namespace {

constexpr int kMaxBT = 64;

void check_cuda_tensor(const at::Tensor& tensor, const char* name)
{
    TORCH_CHECK(tensor.is_cuda(),
                "chunk_gated_delta_rule_fwd_kkt_solve_hip: ", name,
                " must be a CUDA/HIP tensor");
}

void check_last_contiguous(const at::Tensor& tensor, const char* name)
{
    TORCH_CHECK(tensor.stride(-1) == 1,
                "chunk_gated_delta_rule_fwd_kkt_solve_hip: ", name,
                " must have contiguous last dimension");
}

int ceildiv_int(int a, int b)
{
    return (a + b - 1) / b;
}

void set_kkt_solve_params(
    FLA_NAMESPACE::KktSolveParams &params,
    at::Tensor &k,
    std::optional<at::Tensor> &g,
    at::Tensor &beta,
    at::Tensor &A,
    std::optional<at::Tensor> &cu_seqlens,
    std::optional<at::Tensor> &chunk_indices,
    int B,
    int T,
    int H,
    int Hg,
    int K,
    int BT,
    int NT,
    bool is_varlen)
{
    params = {};

    params.k_ptr = k.data_ptr();
    params.g_ptr = g.has_value() && g->defined() ? g->data_ptr() : nullptr;
    params.beta_ptr = beta.data_ptr();
    params.A_ptr = A.data_ptr();
    params.cu_seqlens =
        is_varlen && cu_seqlens.has_value() ? cu_seqlens->data_ptr() : nullptr;
    params.chunk_indices =
        is_varlen && chunk_indices.has_value() ? chunk_indices->data_ptr() : nullptr;

    params.B = B;
    params.T = T;
    params.H = H;
    params.Hg = Hg;
    params.K = K;
    params.BT = BT;
    params.NT = NT;

    params.use_g = g.has_value() && g->defined();
    params.is_varlen = is_varlen;
    params.beta_is_float = beta.scalar_type() == at::ScalarType::Float;
    params.cu_seqlens_i64 =
        is_varlen && cu_seqlens.has_value() &&
        cu_seqlens->scalar_type() == at::ScalarType::Long;
    params.chunk_indices_i64 =
        is_varlen && chunk_indices.has_value() &&
        chunk_indices->scalar_type() == at::ScalarType::Long;
}

void run_kkt_solve_by_dtype(
    FLA_NAMESPACE::KktSolveParams &params,
    at::ScalarType dtype,
    hipStream_t stream)
{
    if (dtype == at::ScalarType::Half) {
        FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_kkt_solve_fp16(params, stream);
    } else if (dtype == at::ScalarType::BFloat16) {
        FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_kkt_solve_bf16(params, stream);
    } else {
        TORCH_CHECK(false,
                    "chunk_gated_delta_rule_fwd_kkt_solve_hip: unsupported dtype");
    }
}

}  // namespace

at::Tensor chunk_gated_delta_rule_fwd_kkt_solve_hip(
    at::Tensor const &k,
    at::Tensor const &beta,
    std::optional<at::Tensor> const &g,
    std::optional<at::Tensor> const &cu_seqlens,
    std::optional<at::Tensor> const &chunk_indices,
    int const chunk_size)
{
    check_cuda_tensor(k, "k");
    check_cuda_tensor(beta, "beta");
    check_last_contiguous(k, "k");

    TORCH_CHECK(k.dim() == 4,
                "chunk_gated_delta_rule_fwd_kkt_solve_hip: k must be [B, T, Hg, K]");
    TORCH_CHECK(beta.dim() == 3,
                "chunk_gated_delta_rule_fwd_kkt_solve_hip: beta must be [B, T, H]");
    TORCH_CHECK(
        k.scalar_type() == at::ScalarType::Half ||
            k.scalar_type() == at::ScalarType::BFloat16,
        "chunk_gated_delta_rule_fwd_kkt_solve_hip: k must be fp16 or bf16");
    TORCH_CHECK(
        beta.scalar_type() == at::ScalarType::Float || beta.scalar_type() == k.scalar_type(),
        "chunk_gated_delta_rule_fwd_kkt_solve_hip: beta must be fp32 or match k dtype");
    TORCH_CHECK(chunk_size > 0 && chunk_size <= kMaxBT,
                "chunk_gated_delta_rule_fwd_kkt_solve_hip: chunk_size must be in (0, 64]");

    const bool is_varlen = cu_seqlens.has_value() && cu_seqlens->defined();
    const int B = static_cast<int>(k.size(0));
    const int T = static_cast<int>(k.size(1));
    const int Hg = static_cast<int>(k.size(2));
    const int K = static_cast<int>(k.size(3));
    const int H = static_cast<int>(beta.size(2));

    TORCH_CHECK(beta.size(0) == B && beta.size(1) == T,
                "chunk_gated_delta_rule_fwd_kkt_solve_hip: beta batch/token dimensions must match k");
    TORCH_CHECK(H % Hg == 0,
                "chunk_gated_delta_rule_fwd_kkt_solve_hip: H must be divisible by Hg");
    TORCH_CHECK(!is_varlen || B == 1,
                "chunk_gated_delta_rule_fwd_kkt_solve_hip: varlen path expects packed batch size 1");
    TORCH_CHECK(
        B <= std::numeric_limits<int>::max() &&
            T <= std::numeric_limits<int>::max() &&
            H <= std::numeric_limits<int>::max() &&
            Hg <= std::numeric_limits<int>::max() &&
            K <= std::numeric_limits<int>::max(),
        "chunk_gated_delta_rule_fwd_kkt_solve_hip: tensor dimensions are too large");

    if (g.has_value() && g->defined()) {
        check_cuda_tensor(*g, "g");
        TORCH_CHECK(g->dtype() == at::ScalarType::Float,
                    "chunk_gated_delta_rule_fwd_kkt_solve_hip: g must be fp32");
        TORCH_CHECK(g->dim() == 3 && g->size(0) == B && g->size(1) == T && g->size(2) == H,
                    "chunk_gated_delta_rule_fwd_kkt_solve_hip: g must be [B, T, H]");
        check_last_contiguous(*g, "g");
    }

    int NT = ceildiv_int(T, chunk_size);
    if (is_varlen) {
        check_cuda_tensor(*cu_seqlens, "cu_seqlens");
        TORCH_CHECK(cu_seqlens->dim() == 1 && cu_seqlens->size(0) >= 2,
                    "chunk_gated_delta_rule_fwd_kkt_solve_hip: cu_seqlens must be 1D with at least 2 elements");
        TORCH_CHECK(cu_seqlens->scalar_type() == at::ScalarType::Int ||
                        cu_seqlens->scalar_type() == at::ScalarType::Long,
                    "chunk_gated_delta_rule_fwd_kkt_solve_hip: cu_seqlens must be int32 or int64");
        TORCH_CHECK(chunk_indices.has_value() && chunk_indices->defined(),
                    "chunk_gated_delta_rule_fwd_kkt_solve_hip: chunk_indices is required for varlen");
        check_cuda_tensor(*chunk_indices, "chunk_indices");
        TORCH_CHECK(chunk_indices->dim() == 2 && chunk_indices->size(1) == 2,
                    "chunk_gated_delta_rule_fwd_kkt_solve_hip: chunk_indices must be [NT, 2]");
        TORCH_CHECK(chunk_indices->scalar_type() == at::ScalarType::Int ||
                        chunk_indices->scalar_type() == at::ScalarType::Long,
                    "chunk_gated_delta_rule_fwd_kkt_solve_hip: chunk_indices must be int32 or int64");
        NT = static_cast<int>(chunk_indices->size(0));
    }

    auto k_contig = k.contiguous();
    auto beta_contig = beta.contiguous();

    std::optional<at::Tensor> g_contig = std::nullopt;
    if (g.has_value() && g->defined()) {
        g_contig = g->contiguous();
    }

    std::optional<at::Tensor> cu_contig = std::nullopt;
    std::optional<at::Tensor> chunk_indices_contig = std::nullopt;
    if (is_varlen) {
        cu_contig = cu_seqlens->contiguous();
        chunk_indices_contig = chunk_indices->contiguous();
    }

    const bool kernel_initializes_zero_regions = K == 128 && chunk_size == kMaxBT;
    at::Tensor A = kernel_initializes_zero_regions
        ? at::empty({B, T, H, chunk_size}, k.options())
        : at::zeros({B, T, H, chunk_size}, k.options());
    if (A.numel() == 0 || NT == 0) {
        return A;
    }

    FLA_NAMESPACE::KktSolveParams params;
    set_kkt_solve_params(
        params, k_contig, g_contig, beta_contig, A, cu_contig,
        chunk_indices_contig, B, T, H, Hg, K, chunk_size, NT, is_varlen);

    const hipStream_t stream = at::hip::getCurrentHIPStream();
    run_kkt_solve_by_dtype(params, k_contig.scalar_type(), stream);

    AITER_HIP_KERNEL_LAUNCH_CHECK();
    return A;
}
