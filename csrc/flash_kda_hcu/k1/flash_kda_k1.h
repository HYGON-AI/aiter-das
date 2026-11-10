// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#pragma once

#include <torch/all.h>
#include <torch/extension.h>

// K1 生产模块：直接写出 K2 消费的 workspace，支持定长尾块与 packed 变长。
// 不导出、不覆盖既有 module_flash_kda_hcu 的任何符号。
void kda_k1_forward(
    torch::Tensor q,
    torch::Tensor k,
    torch::Tensor g,
    torch::Tensor beta,
    torch::Tensor A_log,
    torch::Tensor dt_bias,
    double scale,
    double lower_bound,
    torch::Tensor ws_kd_a,
    torch::Tensor ws_kr_a,
    torch::Tensor ws_inv_a,
    torch::Tensor ws_mqk_a,
    torch::Tensor beta_sigmoid,
    bool write_beta_fp32);

// ---------------------------------------------------------------------------
// 变长：GPU metadata + packed 变长实例。
// 元数据契约见 flash_kda_varlen_metadata.cuh；分配只由 shape 决定，host 不回读 GPU 内容。
// ---------------------------------------------------------------------------
void kda_k1_varlen_forward(
    torch::Tensor q,
    torch::Tensor k,
    torch::Tensor g,
    torch::Tensor beta,
    torch::Tensor A_log,
    torch::Tensor dt_bias,
    double scale,
    double lower_bound,
    torch::Tensor ws_kd_a,
    torch::Tensor ws_kr_a,
    torch::Tensor ws_inv_a,
    torch::Tensor ws_mqk_a,
    torch::Tensor beta_sigmoid,
    torch::Tensor chunk_info);

void kda_build_varlen_metadata(
    torch::Tensor cu_seqlens,
    torch::Tensor chunk_info,
    torch::Tensor sequence_info);

#define FLASH_KDA_K1_VARLEN_FORWARD_PYBIND                                   \
    m.def("kda_k1_varlen_forward", &kda_k1_varlen_forward,                   \
          "peer direct varlen: packed inputs + chunk_info -> C16 workspace", \
          py::arg("q"), py::arg("k"), py::arg("g"), py::arg("beta"),         \
          py::arg("A_log"), py::arg("dt_bias"), py::arg("scale"),            \
          py::arg("lower_bound"), py::arg("ws_kd_a"), py::arg("ws_kr_a"),    \
          py::arg("ws_inv_a"), py::arg("ws_mqk_a"), py::arg("beta_sigmoid"), \
          py::arg("chunk_info"))

#define FLASH_KDA_BUILD_VARLEN_METADATA_PYBIND                                   \
    m.def("kda_build_varlen_metadata", &kda_build_varlen_metadata,               \
          "Build GPU varlen metadata (chunk_info[Qcap,2] + sequence_info[N,3])", \
          py::arg("cu_seqlens"), py::arg("chunk_info"), py::arg("sequence_info"))

#define FLASH_KDA_K1_FORWARD_PYBIND                                       \
    m.def("kda_k1_forward", &kda_k1_forward,                              \
          "Run reference K1 writing the C16 K2 workspace directly",       \
          py::arg("q"), py::arg("k"), py::arg("g"), py::arg("beta"),      \
          py::arg("A_log"), py::arg("dt_bias"), py::arg("scale"),         \
          py::arg("lower_bound"), py::arg("ws_kd_a"), py::arg("ws_kr_a"), \
          py::arg("ws_inv_a"), py::arg("ws_mqk_a"),                       \
          py::arg("beta_sigmoid"), py::arg("write_beta_fp32"))
