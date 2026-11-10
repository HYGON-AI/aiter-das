// SPDX-License-Identifier: MIT
#pragma once

// FlashKDA 统一 native forward 的公开契约（host 侧唯一入口）。

#include <torch/all.h>
#include <torch/extension.h>

#include <cstdint>
#include <optional>
#include <tuple>

#include "flash_kda_workspace.h"

namespace flash_kda
{

    // 输入特性位：公开入口把若干 bool 压成一个 int 传入，避免逐层 kwargs。
    // 每个位对应一项输入差异；state_v_first 位对应外部 state 的物理布局。
    enum InputFeature : int64_t
    {
        kFeatureQkL2Norm = 1 << 0,
        kFeatureGate = 1 << 1,
        kFeatureBetaSigmoid = 1 << 2,
        kFeatureSafeGate = 1 << 3,
        kFeatureStateVFirst = 1 << 4,
        kFeatureDisableRecompute = 1 << 5,
    };

    // HCU 准入的必备位：低四位全开（l2norm/gate/beta_sigmoid/safe_gate）。
    constexpr int64_t kHcuRequiredFeatures =
        kFeatureQkL2Norm | kFeatureGate | kFeatureBetaSigmoid | kFeatureSafeGate;

    // 可选位：state_v_first 只切换外部 state 的存储布局，不改变计算路径。
    constexpr int64_t kHcuOptionalFeatures = kFeatureStateVFirst;
    // 允许出现的全部位（越界位一律按不支持处理）。
    constexpr int64_t kHcuAllowedFeatures = kHcuRequiredFeatures | kHcuOptionalFeatures;

} // namespace flash_kda

// 唯一 forward：成功返回 (out, final_state_or_None)。
// `allow_fallback=true` 时对"合法但 HCU 不支持"的输入返回两个未定义 Tensor（Python None）。
std::tuple<torch::Tensor, torch::Tensor> kda_forward(
    const torch::Tensor &q,
    const torch::Tensor &k,
    const torch::Tensor &v,
    const torch::Tensor &g,
    const torch::Tensor &beta,
    const std::optional<torch::Tensor> &A_log,
    const std::optional<torch::Tensor> &dt_bias,
    const std::optional<double> &scale,
    const std::optional<double> &lower_bound,
    const std::optional<torch::Tensor> &initial_state,
    bool output_final_state,
    const std::optional<at::ScalarType> &state_dtype,
    const std::optional<torch::Tensor> &cu_seqlens,
    int64_t features,
    const std::optional<int64_t> &chunk_size,
    bool allow_fallback,
    bool normalize_inputs,
    const std::optional<torch::Tensor> &out,
    const std::optional<torch::Tensor> &final_state,
    const std::optional<torch::Tensor> &workspace);

// 冷路径容量查询（两个标量返回值，避免 tuple 返回类型不被 schema 推断支持）。
// `kda_segment_chunks` 返回 0 表示不分段。
int64_t kda_workspace_bytes(int64_t batch, int64_t tokens, int64_t heads,
                            int64_t sequence_count, bool is_varlen);
int64_t kda_segment_chunks(int64_t batch, int64_t tokens, int64_t heads);

#define FLASH_KDA_FORWARD_PYBIND                                                            \
    m.def("kda_forward", &kda_forward, "FlashKDA unified native forward",                    \
          py::arg("q"), py::arg("k"), py::arg("v"), py::arg("g"), py::arg("beta"),           \
          py::arg("A_log") = py::none(), py::arg("dt_bias") = py::none(),                    \
          py::arg("scale") = py::none(), py::arg("lower_bound") = py::none(),                \
          py::arg("initial_state") = py::none(), py::arg("output_final_state") = false,      \
          py::arg("state_dtype") = py::none(), py::arg("cu_seqlens") = py::none(),           \
          py::arg("features") = 0, py::arg("chunk_size") = py::none(),                       \
          py::arg("allow_fallback") = false, py::arg("normalize_inputs") = false,            \
          py::arg("out") = py::none(), py::arg("final_state") = py::none(),                  \
          py::arg("workspace") = py::none())

#define FLASH_KDA_WORKSPACE_SPEC_PYBIND                                                       \
    m.def("kda_workspace_bytes", &kda_workspace_bytes,                                        \
          "FlashKDA scratch byte size for one forward",                                       \
          py::arg("batch"), py::arg("tokens"), py::arg("heads"),                              \
          py::arg("sequence_count") = 1, py::arg("is_varlen") = false);                       \
    m.def("kda_segment_chunks", &kda_segment_chunks,                                          \
          "FlashKDA segment granularity (0 = no segmentation)",                              \
          py::arg("batch"), py::arg("tokens"), py::arg("heads"))
