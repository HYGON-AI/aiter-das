# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""FlashKDA 的独立 Triton 参考与数值判定。

参考路径固定为 ``aiter.ops.triton.kimi_delta_attn.flash_kda.flash_kda_fwd``：
不经 HCU/auto 分派，不调用公开兼容入口，也不导入 benchmark 或阶段 executor。
因此这里给出的是**算法层**对照，而不是"同一 native 实现的封装一致性"。

``measure_error`` 是本目录唯一的 metric 定义：非有限值一律判失败（不能靠 NaN 比较
或忽略 NaN 让用例通过），空张量单独处理。
"""

from __future__ import annotations

import torch

from op_tests.flash_kda import cases


def _varlen_lengths(cu_seqlens):
    """从 cu_seqlens 读出每条序列的长度（参考侧允许一次 D2H；生产路径不允许）。"""
    bounds = [int(v) for v in cu_seqlens.detach().cpu().tolist()]
    return [stop - start for start, stop in zip(bounds, bounds[1:])]


def triton_reference(x, *, want_final, state_v_first=False):
    """用 Triton 独立实现算出一组输入的 ``(out, final_state)`` 参考。

    * ``state_v_first`` 与待测调用保持一致（``False``=KV ``[K,V]``，``True``=VK ``[V,K]``）
    * BF16 初态在参考侧提升 FP32：递推恒 FP32，终态按既有外部 dtype 规则处理
    * 变长输入**逐序列**调用定长 Triton 实现：融合变长 Triton 路径对"长度为 0 的
      序列"会产出 NaN（后续序列一起被污染），不能作为空序列 case 的参考。逐序列
      调用在数学上等价（packed 路径各序列互不传递状态），并且天然覆盖空序列：
      空序列没有输出 token，终态直接等于自己的初态。
    """
    # 函数内 import：收集阶段不得触发 JIT/GPU 初始化。
    from aiter.ops.triton.kimi_delta_attn.flash_kda import flash_kda_fwd

    def run_fused(q, k, v, g, beta, state, cu):
        return flash_kda_fwd(
            q, k, v, g, beta, x["A_log"], x["dt_bias"],
            float(x.get("scale", cases.SCALE)),
            float(x.get("lower_bound", cases.LOWER_BOUND)),
            initial_state=state,
            output_final_state=bool(want_final),
            state_v_first=bool(state_v_first),
            cu_seqlens=cu,
        )

    state = x.get("state")
    if state is not None and state.dtype is torch.bfloat16:
        state = state.float()
    cu = x.get("cu_seqlens")
    if cu is None:
        return run_fused(x["q"], x["k"], x["v"], x["g"], x["beta"], state, None)

    lengths = _varlen_lengths(cu)
    heads = x["q"].shape[2]
    out = torch.empty_like(x["v"])
    final = None
    if want_final:
        final = torch.zeros((len(lengths), heads, cases.KEY_DIM, cases.VALUE_DIM),
                            dtype=torch.float32, device=x["v"].device)
    start = 0
    for seq, length in enumerate(lengths):
        if length == 0:
            if want_final:
                final[seq] = 0.0 if state is None else state[seq]
            continue
        stop = start + length
        part_state = None if state is None else state[seq:seq + 1]
        piece_out, piece_final = run_fused(
            x["q"][:, start:stop], x["k"][:, start:stop], x["v"][:, start:stop],
            x["g"][:, start:stop], x["beta"][:, start:stop], part_state, None,
        )
        out[:, start:stop] = piece_out
        if want_final:
            final[seq] = piece_final[0]
        start = stop
    assert start == x["v"].shape[1]
    return out, final


def measure_error(actual, expected, *, max_abs_limit=cases.OUT_MAX_ABS,
                  relative_l2_limit=cases.OUT_REL_L2):
    """对照两个张量并返回可断言/可落盘的度量字典。

    ``relative_l2 = ‖Δ‖ / (‖ref‖ + 1e-6)``；``nbad`` 是 ``|Δ| > max_abs_limit`` 的元素数。
    门限语义沿用既有验收：``max_abs <= limit`` 且 ``relative_l2 < limit``。
    """
    if tuple(actual.shape) != tuple(expected.shape):
        raise AssertionError(f"shape mismatch: {tuple(actual.shape)} vs {tuple(expected.shape)}")
    actual_fp = actual.float()
    expected_fp = expected.float()
    finite = bool(torch.isfinite(actual_fp).all().item()
                  and torch.isfinite(expected_fp).all().item())
    record = {
        "finite": finite,
        "max_abs": 0.0,
        "relative_l2": 0.0,
        "nbad": 0,
        "max_abs_limit": float(max_abs_limit),
        "relative_l2_limit": float(relative_l2_limit),
        "numel": int(actual_fp.numel()),
    }
    if actual_fp.numel() == 0:
        # 空张量：只要求"有限"这一点成立（空集合上没有 max 可取）。
        record["pass"] = finite
        return record
    delta = actual_fp - expected_fp
    delta_finite = torch.isfinite(delta)
    magnitude = torch.where(delta_finite, delta.abs(),
                            torch.full_like(delta, float("inf")))
    record["max_abs"] = float(magnitude.max().item())
    record["nbad"] = int((magnitude > float(max_abs_limit)).sum().item())
    if finite:
        record["relative_l2"] = float(
            (delta.norm() / (expected_fp.norm() + 1e-6)).item()
        )
    else:
        record["relative_l2"] = float("inf")
    record["pass"] = bool(
        finite
        and record["max_abs"] <= float(max_abs_limit)
        and record["relative_l2"] < float(relative_l2_limit)
    )
    return record


def assert_close(actual, expected, *, what, max_abs_limit=cases.OUT_MAX_ABS,
                 relative_l2_limit=cases.OUT_REL_L2):
    """``measure_error`` 的断言包装：失败信息带上 what 与实际度量。"""
    record = measure_error(actual, expected,
                           max_abs_limit=max_abs_limit,
                           relative_l2_limit=relative_l2_limit)
    assert record["pass"], f"{what} mismatch: {record}"
    return record
