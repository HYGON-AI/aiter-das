// SPDX-License-Identifier: MIT
// Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#pragma once

#include "aiter_tensor.h"
#include <cstdint>

namespace aiter {

// DSV4 rotate / rope+rotate activation (module_dsv4_rotate_quant).
//
// HYGON architecture cuts (doc/transplant_github_aiter_ops/):
//   * Upstream's `rotate_activation_fp4quant`, `rope_rotate_activation_fp4quant`
//     and `rmsnorm_rope_rotate_activation_fp4quant_kvcache` are not ported: all
//     three exist only to emit packed e2m1 with an e8m0 block scale, and no HCU
//     target (gfx936 / gfx938 / gfx946) has fp4 hardware. Dropping them also
//     drops the e8m0 scale-layout and KV-preshuffle helpers they needed.
//   * `rope_rotate_activation_fp8quant` is compiled only under GPU_ENABLE_FP8,
//     i.e. on gfx938 / gfx946 / gfx92a. gfx936 has no packed fp8 conversion.
//
// Shapes: input is [..., head_num, dim] with dim in {128, 256, 512, 1024} and
// head_num a power of two. `positions` is int64 with one entry per token
// (numel / head_num / dim rows).

// Hadamard rotate only, bf16/fp16 in place (out shares dtype/stride with input).
void rotate_activation(aiter_tensor_t& out, const aiter_tensor_t& input);

// GPT-J (interleaved) RoPE over the trailing rope_dim, then Hadamard rotate.
// bf16/fp16 in place (out shares dtype/stride with input).
void rope_rotate_activation(aiter_tensor_t& out,
                            const aiter_tensor_t& input,
                            const aiter_tensor_t& cos,
                            const aiter_tensor_t& sin,
                            const aiter_tensor_t& positions,
                            int32_t rope_dim,
                            bool do_rotate_act = true);

#ifdef GPU_ENABLE_FP8
// rope+hadamard, then fp8-quantize: `out` is fp8 and `out_scale` receives
// per-(row, 1xGROUP) fp32 scales ([m, dim/group_size]), matching
// get_hip_quant(per_1x128).
void rope_rotate_activation_fp8quant(aiter_tensor_t& out,
                                     aiter_tensor_t& out_scale,
                                     const aiter_tensor_t& input,
                                     const aiter_tensor_t& cos,
                                     const aiter_tensor_t& sin,
                                     const aiter_tensor_t& positions,
                                     int32_t rope_dim,
                                     int32_t group_size = 128,
                                     bool do_rotate_act = true);
#endif

} // namespace aiter
