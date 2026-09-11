// SPDX-License-Identifier: MIT
// Copyright (C) 2025-2026, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#pragma once

#include <torch/all.h>
#include <torch/extension.h>

void opus_gemm_a16w16_hcu(torch::Tensor& XQ,
                          torch::Tensor& WQ,
                          torch::Tensor& Y,
                          torch::Tensor& Bias,
                          torch::Tensor& Workspace,
                          int split_k,
                          int kernel_id);

void opus_gemm_a8w8_gfx938(torch::Tensor& XQ,
                           torch::Tensor& WQ,
                           torch::Tensor& Y,
                           torch::Tensor& Bias,
                           float scale_ab,
                           int kernel_id);

#define OPUS_GEMM_A16W16_HCU_PYBIND                                            \
    m.def("opus_gemm_a16w16_hcu",                                             \
          &opus_gemm_a16w16_hcu,                                               \
          "BF16 Opus GEMM implemented with the gfx936/gfx938/gfx946 HCU MMAC path", \
          py::arg("XQ"), py::arg("WQ"), py::arg("Y"),                      \
          py::arg("Bias"), py::arg("Workspace"),                            \
          py::arg("split_k"), py::arg("kernel_id"))

#define OPUS_GEMM_A8W8_GFX938_PYBIND                                           \
    m.def("opus_gemm_a8w8_gfx938",                                            \
          &opus_gemm_a8w8_gfx938,                                              \
          "FP8 Opus GEMM implemented with the gfx938/gfx946 HCU MMAC path",   \
          py::arg("XQ"), py::arg("WQ"), py::arg("Y"),                     \
          py::arg("Bias"), py::arg("scale_ab"), py::arg("kernel_id"))
