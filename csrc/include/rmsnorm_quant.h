// SPDX-License-Identifier: MIT
// Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#pragma once

#include "aiter_tensor.h"

namespace aiter {

// Fast HIP RMSNorm family (module_rmsnorm_quant). Independent of the CK / opus
// rmsnorm2d_* entries in module_rmsnorm: these take aiter_tensor_t, support
// n <= 8192 only, and add grouped (1xG) / shuffled / e8m0 scale layouts on top
// of the per-token fp32 scale the CK path already provides.
//
// HYGON architecture notes (see doc/transplant_github_aiter_ops/):
//   * fp8 output and the e8m0 (1-byte) block scale are compiled only when
//     GPU_ENABLE_FP8 is defined, i.e. on gfx938 / gfx946 / gfx92a. On gfx936
//     opus::fp32_to_fp8_packed_x2 has no HW instruction and silently yields
//     zeros, so the entry points reject an fp8 `out` there instead.
//   * fp4x2 output is removed outright -- no e2m1 HW support on any HCU target.
//   * scale_layout_m32k4 feeds a gfx1250 MXFP8 ASM GEMM that does not exist on
//     HCU; the parameter is kept for signature parity and rejected at runtime.

void add_rmsnorm_quant(aiter_tensor_t& out,
                       aiter_tensor_t& input,
                       aiter_tensor_t& residual_in,
                       aiter_tensor_t& residual_out,
                       aiter_tensor_t& scale,
                       aiter_tensor_t& weight,
                       double epsilon,
                       int group_size          = 0,
                       bool shuffle_scale      = false,
                       bool gemma_norm         = false,
                       bool scale_layout_m32k4 = false);

void add_rmsnorm(aiter_tensor_t& out,
                 aiter_tensor_t& input,
                 aiter_tensor_t& residual_in,
                 aiter_tensor_t& residual_out,
                 aiter_tensor_t& weight,
                 double epsilon,
                 bool gemma_norm = false);

void rmsnorm_quant(aiter_tensor_t& out,
                   aiter_tensor_t& input,
                   aiter_tensor_t& scale,
                   aiter_tensor_t& weight,
                   double epsilon,
                   int group_size          = 0,
                   bool shuffle_scale      = false,
                   bool gemma_norm         = false,
                   bool scale_layout_m32k4 = false);

void rmsnorm(aiter_tensor_t& out,
             aiter_tensor_t& input,
             aiter_tensor_t& weight,
             double epsilon,
             bool gemma_norm = false);

} // namespace aiter
