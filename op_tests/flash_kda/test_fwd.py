# SPDX-License-Identifier: MIT
"""FlashKDA 数值覆盖：定长（F01–F08）与变长（V01–V06）对照独立 Triton 参考。

参考路径固定为 `reference.triton_reference`（`kimi_delta_attn.flash_kda.flash_kda_fwd`），
不经过 HCU/auto 分派，因此这是**算法层**对照，不是同一 native 实现的封装等价。

门槛（沿用既有验收口径，未放宽）：

| 对照对象 | max_abs | relative_l2 |
|---|---|---|
| out vs 独立 Triton 参考 | `cases.OUT_MAX_ABS = 0.02` | `cases.OUT_REL_L2 = 0.02` |
| final_state vs 独立 Triton 参考 | `cases.STATE_MAX_ABS = 0.05` | `cases.STATE_REL_L2 = 0.05` |
| 分段(auto) vs 强制 plain（同输入，非参考对照） | `0.02` | `0.005` |

case 与迁移来源见执行计划 B3；旧记录里的 smoke 数值只作为输入来源，不作为本文件的
验证结果。
"""

import pytest
import torch

from op_tests.flash_kda import cases, reference

pytestmark = pytest.mark.gpu

#: 同输入不同路径（auto 分段 vs 强制 plain）的对照门槛，沿用 acceptance probe 口径
CROSS_PATH_MAX_ABS = 0.02
CROSS_PATH_REL_L2 = 0.005


def _run(x, *, initial_state="auto", want_final=True):
    """用用户主入口跑一次，返回 ``(out, final)``；``initial_state="auto"`` 用 x["state"]。"""
    from aiter.ops.flash_kda import fwd

    state = x["state"] if initial_state == "auto" else initial_state
    out = torch.empty_like(x["v"])
    final = torch.empty_like(x["state"]) if want_final else None
    result = fwd(
        x["q"], x["k"], x["v"], x["g"], x["beta"], cases.SCALE, out,
        x["A_log"], x["dt_bias"], cases.LOWER_BOUND,
        initial_state=state, final_state=final, cu_seqlens=x["cu_seqlens"],
    )
    assert result is None
    return out, final


def _check(x, *, out, final, want_final=True, label="case", state_dtype=None):
    """对照独立 Triton 参考并断言门槛。"""
    ref_out, ref_final = reference.triton_reference(x, want_final=want_final)
    out_record = reference.assert_close(out, ref_out, what=f"{label} out")
    record = {"out": out_record}
    if want_final:
        if ref_final is None or final is None:
            raise AssertionError(f"{label}: final_state requested but reference returned None")
        expected_dtype = state_dtype if state_dtype is not None else x["state"].dtype
        if final.dtype != expected_dtype:
            raise AssertionError(f"{label}: final dtype {final.dtype} != {expected_dtype}")
        record["final_state"] = reference.assert_close(
            final, ref_final, what=f"{label} final_state",
            max_abs_limit=cases.STATE_MAX_ABS,
            relative_l2_limit=cases.STATE_REL_L2,
        )
    return record


# ---------------------------------------------------------------------------
# 定长 F01–F07
# ---------------------------------------------------------------------------
@pytest.mark.parametrize("case_id,shape,state_dtype", cases.fixed_case_params())
def test_fixed_matches_triton(gpu, case_id, shape, state_dtype):
    x = cases.make_inputs(shape, seed=cases.case_seed(case_id), state_dtype=state_dtype)
    out, final = _run(x)
    _check(x, out=out, final=final, label=case_id)


def test_f07_forces_segmented_route(gpu):
    """F07 的输入在当前路由下必须真的走分段，否则这条 case 名不副实。"""
    from aiter.ops.opus.flash_kda_route import c16_segment_chunks

    batch, tokens, heads = cases.F08_SHAPE
    assert c16_segment_chunks(batch, tokens, heads) == 32


def test_f08_force_plain_matches_triton_and_auto(gpu, monkeypatch):
    """F08：同输入、强制 plain，与自动分段和独立参考分别对照（不比耗时）。"""
    x = cases.make_inputs(cases.F08_SHAPE, seed=cases.case_seed("F08"),
                          state_dtype=torch.float32)
    monkeypatch.delenv("FLASH_KDA_HCU_SEGMENT", raising=False)
    auto_out, auto_final = _run(x)
    auto_record = _check(x, out=auto_out, final=auto_final, label="F08-auto")

    monkeypatch.setenv("FLASH_KDA_HCU_SEGMENT", "0")
    plain_out, plain_final = _run(x)
    plain_record = _check(x, out=plain_out, final=plain_final, label="F08-plain")

    reference.assert_close(plain_out, auto_out, what="F08 plain-vs-auto out",
                           max_abs_limit=CROSS_PATH_MAX_ABS,
                           relative_l2_limit=CROSS_PATH_REL_L2)
    reference.assert_close(plain_final, auto_final, what="F08 plain-vs-auto final_state",
                           max_abs_limit=cases.STATE_MAX_ABS,
                           relative_l2_limit=CROSS_PATH_REL_L2)
    assert auto_record["out"]["pass"] and plain_record["out"]["pass"]


# ---------------------------------------------------------------------------
# 变长 V01–V05
# ---------------------------------------------------------------------------
@pytest.mark.parametrize("case_id,lengths,heads,state_dtype", cases.varlen_case_params())
def test_varlen_matches_triton(gpu, case_id, lengths, heads, state_dtype):
    x = cases.make_inputs((1, sum(lengths), heads), seed=cases.case_seed(case_id),
                          state_dtype=state_dtype, lengths=lengths)
    out, final = _run(x)
    if sum(lengths) == 0:
        # V05：T=0 时独立 Triton 参考无法表达——`_choose_chunks_per_seg` 对 0 个 chunk
        # 会得到 chunks_per_seg=0，随后 cdiv 除零。该 case 的契约本身是结构性的：
        # 输出为空、终态逐位等于初态。这里按契约断言，不当作"通过"的 skip。
        assert tuple(out.shape) == (1, 0, heads, 128)
        assert out.numel() == 0
        assert torch.equal(final, x["state"])
        return
    _check(x, out=out, final=final, label=case_id)


def test_v06_same_total_different_partition(gpu):
    """V06：同 shape（T=33、H=6）的两种 cu 分区都必须各自对照独立参考。"""
    for lengths in cases.V06_PARTITIONS:
        x = cases.make_inputs((1, sum(lengths), cases.V06_HEADS),
                              seed=cases.case_seed("V06") + sum(lengths),
                              state_dtype=torch.float32, lengths=lengths)
        out, final = _run(x)
        _check(x, out=out, final=final, label=f"V06{lengths}")


# ---------------------------------------------------------------------------
# B4：状态组合（无/有初态 × 无/有终态 × FP32/BF16）× 定长与变长
# ---------------------------------------------------------------------------
@pytest.mark.parametrize("has_initial", [False, True])
@pytest.mark.parametrize("want_final", [False, True])
@pytest.mark.parametrize("state_dtype", [torch.float32, torch.bfloat16])
def test_state_combinations_fixed(gpu, has_initial, want_final, state_dtype):
    x = cases.make_inputs((2, 33, 6), seed=cases.case_seed("F03"),
                          state_dtype=state_dtype)
    initial = x["state"] if has_initial else None
    out, final = _run(x, initial_state=initial, want_final=want_final)
    ref_x = dict(x)
    ref_x["state"] = initial
    _check(ref_x, out=out, final=final, want_final=want_final, state_dtype=state_dtype,
           label=f"F03 init={has_initial} final={want_final} {state_dtype}")


@pytest.mark.parametrize("has_initial", [False, True])
@pytest.mark.parametrize("want_final", [False, True])
@pytest.mark.parametrize("state_dtype", [torch.float32, torch.bfloat16])
def test_state_combinations_varlen(gpu, has_initial, want_final, state_dtype):
    lengths = [10, 20, 30, 500, 1000, 2001]
    x = cases.make_inputs((1, sum(lengths), 6), seed=cases.case_seed("V02"),
                          state_dtype=state_dtype, lengths=lengths)
    initial = x["state"] if has_initial else None
    out, final = _run(x, initial_state=initial, want_final=want_final)
    ref_x = dict(x)
    ref_x["state"] = initial
    _check(ref_x, out=out, final=final, want_final=want_final, state_dtype=state_dtype,
           label=f"V02 init={has_initial} final={want_final} {state_dtype}")


@pytest.mark.parametrize("case_id,lengths,heads,state_dtype", [
    ("V02-int32", [10, 20, 30, 500, 1000, 2001], 6, torch.float32),
    ("V04-int32", [10, 0, 30, 500, 1000, 2001], 6, torch.float32),
])
def test_varlen_int32_cu(gpu, case_id, lengths, heads, state_dtype):
    x = cases.make_inputs((1, sum(lengths), heads), seed=cases.case_seed(case_id),
                          state_dtype=state_dtype, lengths=lengths)
    x["cu_seqlens"] = x["cu_seqlens"].to(torch.int32)
    out, final = _run(x)
    _check(x, out=out, final=final, label=case_id)


# ---------------------------------------------------------------------------
# B5：state 的 [K,V] 轴顺序（K=V=128 时形状相同，不能只看 shape）
# ---------------------------------------------------------------------------
def test_state_kv_axis_order_is_honoured(gpu):
    x = cases.make_inputs((1, 129, 6), seed=cases.case_seed("state-kv"),
                          state_dtype=torch.float32)
    out, final = _run(x)
    _check(x, out=out, final=final, label="[K,V]")

    transposed = dict(x)
    transposed["state"] = x["state"].transpose(-1, -2).contiguous()
    t_out, t_final = _run(transposed)
    _check(transposed, out=t_out, final=t_final, label="[V,K]-as-different-input")

    # 只证明"初态内容真的被读取"，不主张两者必须相差某个固定阈值。
    assert not torch.equal(out, t_out)


@pytest.mark.parametrize("shape,lengths", [
    ((1, 33, 6), None),
    ((1, 8192, 6), None),
    ((1, 33, 6), [17, 0, 16]),
])
@pytest.mark.parametrize("state_dtype", [torch.float32, torch.bfloat16])
@pytest.mark.parametrize("state_v_first", [False, True])
def test_bf16_beta_matches_same_values_fp32(gpu, monkeypatch, shape, lengths,
                                           state_dtype, state_v_first):
    """比较同一组可表示值的两种 beta 存储类型，并对照独立参考。"""
    from aiter.ops.flash_kda import fwd

    monkeypatch.delenv("FLASH_KDA_HCU_SEGMENT", raising=False)
    x = cases.make_inputs(shape, seed=20261029, state_dtype=state_dtype,
                          lengths=lengths)
    if state_v_first:
        x["state"] = x["state"].transpose(-1, -2).contiguous()
    beta_bf16 = x["beta"].to(torch.bfloat16)
    x["beta"] = beta_bf16.float()
    results = []
    for beta in (beta_bf16, x["beta"]):
        out, final = torch.empty_like(x["v"]), torch.empty_like(x["state"])
        assert fwd(
            x["q"], x["k"], x["v"], x["g"], beta, cases.SCALE, out,
            x["A_log"], x["dt_bias"], cases.LOWER_BOUND,
            initial_state=x["state"], final_state=final,
            cu_seqlens=x["cu_seqlens"], state_v_first=state_v_first,
        ) is None
        results.append((out, final))
    assert torch.equal(results[0][0], results[1][0])
    assert torch.equal(results[0][1], results[1][1])
    ref_out, ref_final = reference.triton_reference(
        x, want_final=True, state_v_first=state_v_first)
    reference.assert_close(results[0][0], ref_out, what="BF16 beta out")
    reference.assert_close(
        results[0][1], ref_final, what="BF16 beta final_state",
        max_abs_limit=cases.STATE_MAX_ABS,
        relative_l2_limit=cases.STATE_REL_L2,
    )
