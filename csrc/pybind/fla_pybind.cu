// SPDX-License-Identifier: MIT
//
// Self-contained pybind for chunk_gated_delta_rule_fwd HIP entry points.
// Intentionally does NOT include "rocm_ops.hpp", which would pull in
// aiter_tensor.h -> aiter_hip_common.h -> ck_tile/core.hpp and force a
// dependency on the CK submodule. This stub only needs torch + pybind11.

#include "fla.h"
#include <pybind11/pybind11.h>
#include <pybind11/stl.h>
#include <torch/extension.h>

namespace py = pybind11;

PYBIND11_MODULE(TORCH_EXTENSION_NAME, m)
{
    m.def("chunk_gated_delta_rule_fwd_vllm_hip_blockdim64",
          &chunk_gated_delta_rule_fwd_vllm_hip_blockdim64,
          "chunk_gated_delta_rule_fwd_vllm_hip_blockdim64: vLLM-aligned HIP wrapper; returns "
          "[h, v_new, final_state] for Triton-style blockdim64 and headDimK=headDimV=128.",
          py::arg("k"), py::arg("w"), py::arg("u"),
          py::arg("g")                     = std::nullopt,
          py::arg("gk")                    = std::nullopt,
          py::arg("initial_state")         = std::nullopt,
          py::arg("initial_state_indices") = std::nullopt,
          py::arg("output_final_state")    = true,
          py::arg("chunk_size")            = 64,
          py::arg("save_new_value")        = true,
          py::arg("cu_seqlens")            = std::nullopt,
          py::arg("chunk_indices")         = std::nullopt,
          py::arg("chunk_offsets")         = std::nullopt,
          py::arg("use_exp2")              = false,
          py::arg("transpose_state_layout") = true);

    m.def("chunk_gated_delta_rule_fwd_sglang_hip_blockdim64",
          &chunk_gated_delta_rule_fwd_sglang_hip_blockdim64,
          "chunk_gated_delta_rule_fwd_sglang_hip_blockdim64: SGLang-aligned HIP wrapper; returns "
          "[h, v_new] and updates initial_state in place for Triton-style blockdim64 and headDimK=headDimV=128.",
          py::arg("k"), py::arg("w"), py::arg("u"),
          py::arg("g")                     = std::nullopt,
          py::arg("gk")                    = std::nullopt,
          py::arg("initial_state")         = std::nullopt,
          py::arg("initial_state_indices") = std::nullopt,
          py::arg("output_final_state")    = true,
          py::arg("chunk_size")            = 64,
          py::arg("save_new_value")        = true,
          py::arg("cu_seqlens")            = std::nullopt,
          py::arg("chunk_indices")         = std::nullopt,
          py::arg("chunk_offsets")         = std::nullopt,
          py::arg("use_exp2")              = false,
          py::arg("transpose_state_layout") = true);

    // Compatibility aliases. Prefer the explicit names above in new callers.
    m.def("chunk_gated_delta_rule_fwd",
          &chunk_gated_delta_rule_fwd,
          "Compatibility alias for chunk_gated_delta_rule_fwd_vllm_hip_blockdim64.",
          py::arg("k"), py::arg("w"), py::arg("u"),
          py::arg("g")                     = std::nullopt,
          py::arg("gk")                    = std::nullopt,
          py::arg("initial_state")         = std::nullopt,
          py::arg("initial_state_indices") = std::nullopt,
          py::arg("output_final_state")    = true,
          py::arg("chunk_size")            = 64,
          py::arg("save_new_value")        = true,
          py::arg("cu_seqlens")            = std::nullopt,
          py::arg("chunk_indices")         = std::nullopt,
          py::arg("chunk_offsets")         = std::nullopt,
          py::arg("use_exp2")              = false,
          py::arg("transpose_state_layout") = true);

    m.def("chunk_gated_delta_rule_fwd_sglang",
          &chunk_gated_delta_rule_fwd_sglang,
          "Compatibility alias for chunk_gated_delta_rule_fwd_sglang_hip_blockdim64.",
          py::arg("k"), py::arg("w"), py::arg("u"),
          py::arg("g")                     = std::nullopt,
          py::arg("gk")                    = std::nullopt,
          py::arg("initial_state")         = std::nullopt,
          py::arg("initial_state_indices") = std::nullopt,
          py::arg("output_final_state")    = true,
          py::arg("chunk_size")            = 64,
          py::arg("save_new_value")        = true,
          py::arg("cu_seqlens")            = std::nullopt,
          py::arg("chunk_indices")         = std::nullopt,
          py::arg("chunk_offsets")         = std::nullopt,
          py::arg("use_exp2")              = false,
          py::arg("transpose_state_layout") = true);
}
