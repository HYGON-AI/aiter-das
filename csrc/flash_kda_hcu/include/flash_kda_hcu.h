// SPDX-License-Identifier: MIT
#pragma once

#include <torch/all.h>
#include <torch/extension.h>

// ===========================================================================
// FlashKDA gfx936 原生 K2。
//
// workspace 契约（数值区由 K1 直写，K2 只读；公开用户入口的 q/k/v/g/beta 不变）：
//   ws_kdqd  [P,2,8,16,16] BF16  每 chunk 8 KiB：kd 4 KiB，紧跟 qd 4 KiB（同一块）
//   ws_krgt  [P,9,16,16]   BF16  每 chunk 4608 B：kr 4 KiB，紧跟 gt 512 B（同一块）
//   ws_inv   [P,1,1,16,16] FP16
//   ws_mqk   [P,1,1,16,16] FP16
//   beta_sigmoid [P,16]    FP32（K1 已激活）
// 索引 p = head * workspace_head_stride_chunks + sequence_chunk_offset + chunk。
// ===========================================================================
void kda_k2_forward(
    const torch::Tensor &ws_kdqd,
    const torch::Tensor &ws_krgt,
    const torch::Tensor &ws_inv,
    const torch::Tensor &ws_mqk,
    const torch::Tensor &v,
    const torch::Tensor &beta_sigmoid,
    torch::Tensor &out,
    const torch::Tensor &initial_state,
    torch::Tensor &final_state,
    bool state_v_first);

#define FLASH_KDA_K2_FORWARD_PYBIND                              \
    m.def("kda_k2_forward", &kda_k2_forward,                     \
          "Run FlashKDA K2 (fixed length) on gfx936",            \
          py::arg("ws_kdqd"), py::arg("ws_krgt"),                \
          py::arg("ws_inv"), py::arg("ws_mqk"),                  \
          py::arg("v"), py::arg("beta_sigmoid"), py::arg("out"), \
          py::arg("initial_state"), py::arg("final_state"),      \
          py::arg("state_v_first") = false)

// packed 变长：参数在定长入口之后追加 sequence_info（INT64 AoS [N,3]：
// sequence_token_offset / L / chunk0）。定长入口的参数列表保持不变。
void kda_k2_varlen_forward(
    const torch::Tensor &ws_kdqd,
    const torch::Tensor &ws_krgt,
    const torch::Tensor &ws_inv,
    const torch::Tensor &ws_mqk,
    const torch::Tensor &v,
    const torch::Tensor &beta_sigmoid,
    torch::Tensor &out,
    const torch::Tensor &initial_state,
    torch::Tensor &final_state,
    const torch::Tensor &sequence_info,
    bool state_v_first);

#define FLASH_KDA_K2_VARLEN_FORWARD_PYBIND                       \
    m.def("kda_k2_varlen_forward", &kda_k2_varlen_forward,       \
          "Run FlashKDA K2 on packed varlen sequence_info",      \
          py::arg("ws_kdqd"), py::arg("ws_krgt"),                \
          py::arg("ws_inv"), py::arg("ws_mqk"),                  \
          py::arg("v"), py::arg("beta_sigmoid"), py::arg("out"), \
          py::arg("initial_state"), py::arg("final_state"),      \
          py::arg("sequence_info"), py::arg("state_v_first") = false)

// ---------------------------------------------------------------------------
// 分段路径（`k2/flash_kda_segment.cu`）：affine pass → 段间 scan → replay。
// ---------------------------------------------------------------------------
void kda_segment_affine_forward(
    const torch::Tensor &ws_kdqd,
    const torch::Tensor &ws_krgt,
    const torch::Tensor &ws_inv,
    const torch::Tensor &v,
    const torch::Tensor &beta_sigmoid,
    torch::Tensor &segment_update,
    torch::Tensor &segment_transition,
    int segment_count,
    int chunks_per_segment);

void kda_segment_replay_forward(
    const torch::Tensor &ws_kdqd,
    const torch::Tensor &ws_krgt,
    const torch::Tensor &ws_inv,
    const torch::Tensor &ws_mqk,
    const torch::Tensor &v,
    const torch::Tensor &beta_sigmoid,
    torch::Tensor &out,
    torch::Tensor &final_state,
    const torch::Tensor &segment_initial_states,
    int segment_count,
    int chunks_per_segment,
    bool state_v_first);

void kda_segment_scan_forward(
    const torch::Tensor &segment_transition,
    const torch::Tensor &segment_update,
    torch::Tensor &segment_initial_states,
    const torch::Tensor &initial_state,
    int segment_count,
    bool state_v_first);

#define FLASH_KDA_SEGMENT_AFFINE_PYBIND                                                                            \
    m.def("kda_segment_affine_forward", &kda_segment_affine_forward, "Run C16 dual affine segment pass on gfx936", \
          py::arg("ws_kdqd"), py::arg("ws_krgt"), py::arg("ws_inv"),                                               \
          py::arg("v"), py::arg("beta_sigmoid"),                                                                   \
          py::arg("segment_update"), py::arg("segment_transition"), py::arg("segment_count"), py::arg("chunks_per_segment"))

#define FLASH_KDA_SEGMENT_REPLAY_PYBIND                                                                         \
    m.def("kda_segment_replay_forward", &kda_segment_replay_forward, "Run C16 segmented FlashKDA K2 on gfx936", \
          py::arg("ws_kdqd"), py::arg("ws_krgt"),                                                               \
          py::arg("ws_inv"), py::arg("ws_mqk"),                                                                 \
          py::arg("v"), py::arg("beta_sigmoid"),                                                                \
          py::arg("out"), py::arg("final_state"), py::arg("segment_initial_states"),                            \
          py::arg("segment_count"), py::arg("chunks_per_segment"), py::arg("state_v_first") = false)

#define FLASH_KDA_SEGMENT_SCAN_PYBIND                                                                  \
    m.def("kda_segment_scan_forward", &kda_segment_scan_forward, "Run C16 HCU affine segment scan",    \
          py::arg("segment_transition"), py::arg("segment_update"), py::arg("segment_initial_states"), \
          py::arg("initial_state"), py::arg("segment_count"), py::arg("state_v_first") = false)
