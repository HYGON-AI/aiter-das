# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""FlashKDA 统一 native 入口的 Python 适配（内部模块，不是用户接口）。

用户入口见 `aiter/ops/flash_kda.py`。本模块只保留冷加载、唯一 native 绑定与内部
`_forward`：不做参数准入，也不复制第二份分派逻辑。

只做参数整理，然后直接调用冷加载后缓存的 pybind 函数（`module_flash_kda_hcu.kda_forward`）：
不经过 torch 自定义 op 的 schema 推断，也不创建 dummy 或空 Tensor 哨兵——
缺省参数原样传 `None`（pybind 侧是 `std::optional`）。
"""

from ...jit.core import compile_ops, get_module

# 输入特性位（与 csrc/flash_kda_hcu/include/flash_kda_forward.h 一致）
FEATURE_QK_L2NORM = 1 << 0
FEATURE_GATE = 1 << 1
FEATURE_BETA_SIGMOID = 1 << 2
FEATURE_SAFE_GATE = 1 << 3
FEATURE_STATE_V_FIRST = 1 << 4
FEATURE_DISABLE_RECOMPUTE = 1 << 5

#: HCU 准入要求：低四位全开；state_v_first 是可选位，disable_recompute 仍必须为 false
HCU_REQUIRED_FEATURES = (
    FEATURE_QK_L2NORM | FEATURE_GATE | FEATURE_BETA_SIGMOID | FEATURE_SAFE_GATE
)

#: 冷加载触发器：只调用一次，之后全部走 get_module 的薄绑定。
@compile_ops("module_flash_kda_hcu", fc_name="kda_workspace_bytes")
def _warm(batch: int, tokens: int, heads: int, sequence_count: int = 1,
          is_varlen: bool = False) -> int: ...


_MODULE = None


def _module():
    """冷加载一次并缓存 module；之后只取 pybind 函数引用（不缓存输入/stream）。"""
    global _MODULE
    if _MODULE is None:
        _warm(1, 1, 1)
        _MODULE = get_module("module_flash_kda_hcu")
    return _MODULE


def _binding():
    return _module().kda_forward


def _features_from_flags(use_qk_l2norm_in_kernel: bool, use_gate_in_kernel: bool,
                         use_beta_sigmoid_in_kernel: bool, safe_gate: bool,
                         state_v_first: bool, disable_recompute: bool) -> int:
    """把 6 个布尔压成一个特性 int（位定义见 native 头）。"""
    return (
        (FEATURE_QK_L2NORM if use_qk_l2norm_in_kernel else 0)
        | (FEATURE_GATE if use_gate_in_kernel else 0)
        | (FEATURE_BETA_SIGMOID if use_beta_sigmoid_in_kernel else 0)
        | (FEATURE_SAFE_GATE if safe_gate else 0)
        | (FEATURE_STATE_V_FIRST if state_v_first else 0)
        | (FEATURE_DISABLE_RECOMPUTE if disable_recompute else 0)
    )


def _spec_binding(name):
    return getattr(_module(), name)


def workspace_spec(batch: int, tokens: int, heads: int, sequence_count: int = 1,
                   is_varlen: bool = False) -> tuple[int, int | None]:
    """冷路径查询：返回 (workspace_bytes, chunks_per_segment_or_None)。"""
    size = int(_spec_binding("kda_workspace_bytes")(int(batch), int(tokens), int(heads),
                                                    int(sequence_count), bool(is_varlen)))
    if is_varlen:
        return size, None
    cps = int(_spec_binding("kda_segment_chunks")(int(batch), int(tokens), int(heads)))
    return size, (cps if cps > 0 else None)


def _forward(q, k, v, g, beta, A_log=None, dt_bias=None, *, scale=None, lower_bound=None,
             initial_state=None, output_final_state=False, state_dtype=None, cu_seqlens=None,
             features=0, chunk_size=None, allow_fallback=False, normalize_inputs=False,
             out=None, final_state=None, workspace=None):
    """唯一 native 调用：可选参数原样传 None，由 pybind 的 std::optional 接收。"""
    return _binding()(
        q, k, v, g, beta, A_log, dt_bias,
        None if scale is None else float(scale),
        None if lower_bound is None else float(lower_bound),
        initial_state, bool(output_final_state), state_dtype, cu_seqlens,
        int(features),
        None if chunk_size is None else int(chunk_size),
        bool(allow_fallback), bool(normalize_inputs),
        out, final_state, workspace,
    )
