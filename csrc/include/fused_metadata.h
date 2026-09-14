// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
// SPDX-License-Identifier: MIT
#pragma once

#include <torch/extension.h>

#include <optional>

// Fused metadata preparation for paged attention inference.
//
// Combines three steps into a single kernel launch:
//   1. cache_seqlens_int32[i] = seq_lens[i] + seq_len_delta
//   2. cu_seqlens_k           = exclusive prefix-sum of cache_seqlens_int32
//      (cu_seqlens_k[0] == 0, cu_seqlens_k[B] == total)
//   3. page_table[i, c]       = req_to_token[req_pool_indices[i], c * page_size]
//                               >> log2(page_size)
//   4. (optional) swa_page_table[i, c] via full_to_swa_mapping
//
// Inputs are passed by value; outputs by reference (in-place semantics).
// seq_lens / req_pool_indices / full_to_swa_mapping each accept int32 or int64;
// every other tensor must be int32 on the same HIP device.
void fused_metadata_kernel_general(
    torch::Tensor seq_lens,
    torch::Tensor req_to_token,
    torch::Tensor req_pool_indices,
    torch::Tensor& cache_seqlens_int32,
    torch::Tensor& cu_seqlens_k,
    torch::Tensor& page_table,
    const std::optional<torch::Tensor>& swa_page_table,
    const std::optional<torch::Tensor>& full_to_swa_mapping,
    int64_t B,
    int64_t max_seq_pages,
    int64_t page_size,
    int64_t seq_len_delta,
    bool use_swa);
