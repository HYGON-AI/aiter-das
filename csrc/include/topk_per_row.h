#pragma once
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include <optional>
#include <torch/extension.h>

namespace aiter {
namespace topk {

void top_k_per_row_prefill(const torch::Tensor& logits,
                           const torch::Tensor& rowStarts,
                           const torch::Tensor& rowEnds,
                           torch::Tensor& indices,
                           int64_t numRows,
                           int64_t stride0,
                           int64_t stride1,
                           int64_t topK);

void top_k_per_row_decode(const torch::Tensor& logits,
                          int64_t next_n,
                          const torch::Tensor& seqLens,
                          torch::Tensor& indices,
                          int64_t numRows,
                          int64_t stride0,
                          int64_t stride1,
                          int64_t topK);

} // namespace topk
} // namespace aiter

// Global wrappers bound by TOPK_PLAIN_PYBIND (implemented in topk_per_row.cu).
// No-values prefill/decode dispatch to histogram kernels in the same TU.
void top_k_per_row_prefill(const torch::Tensor& logits,
                           const torch::Tensor& rowStarts,
                           const torch::Tensor& rowEnds,
                           torch::Tensor& indices,
                           int64_t numRows,
                           int64_t stride0,
                           int64_t stride1,
                           std::optional<torch::Tensor> values = std::nullopt);

void top_k_per_row_decode(const torch::Tensor& logits,
                          int64_t next_n,
                          const torch::Tensor& seqLens,
                          torch::Tensor& indices,
                          int64_t numRows,
                          int64_t stride0,
                          int64_t stride1);
