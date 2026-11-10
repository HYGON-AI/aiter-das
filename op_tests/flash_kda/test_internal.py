# SPDX-License-Identifier: MIT
"""FlashKDA 内部安全回归：workspace 几何、metadata 边界、写回 guard、graph/stream。

这里放的是**必要内部契约**，不是用户 API：workspace 字节几何、metadata 索引、
尾块写回边界、未用槽不被改写、无内部设备分配、graph/stream 行为。

迁移来源：`integration/test_flash_kda_workspace.py`、
`integration/test_flash_kda_native_forward.py`、`diagnostics/probe_output_store_tail.py`、
`diagnostics/test_peer_k1_varlen.py`（索引模型）、`k1/test_peer_k1_k2_varlen.py`（graph）、
`k2/varlen_case_check.py`（毒槽与 guard）。
"""

import pytest
import torch

from op_tests.flash_kda import cases

pytestmark = [pytest.mark.internal, pytest.mark.gpu]

#: 数值区每 chunk 字节：kdqd 8192 + krgt 4608 + gt 512 + inv 512 + mqk 64
NUMERIC_PER_CHUNK = 8192 + 4608 + 512 + 512 + 64  # 13888


def _spec():
    from aiter.ops.opus.flash_kda_forward import workspace_spec

    return workspace_spec


def _forward_mod():
    from aiter.ops.opus import flash_kda_forward

    return flash_kda_forward


# ---------------------------------------------------------------------------
# workspace 几何与 spec 一致性
# ---------------------------------------------------------------------------
def test_fixed_tiny_bytes(gpu):
    """B=1, T=1, H=6 => P=6，数值区 83328 B，无附加区。"""
    size, cps = _spec()(1, 1, 6, 1, False)
    assert size == NUMERIC_PER_CHUNK * 6 == 83328
    assert cps is None


def test_varlen_empty_tokens_bytes(gpu):
    """packed、T_total=0、N=3、H=6 => Qcap=3、P=18，另加 48+72 B 对齐到 128 B。"""
    size, cps = _spec()(1, 0, 6, 3, True)
    numeric = NUMERIC_PER_CHUNK * 18
    assert numeric == 249984
    assert size - numeric == 128
    assert cps is None


def test_fixed_segmented_short_depth(gpu):
    """B=1, T=8192, H=6：plain CTA=12 < 32 且 T<=8192 => CPS=32。"""
    size, cps = _spec()(1, 8192, 6, 1, False)
    assert cps == 32
    chunks = 8192 // 16
    segments = chunks // 32
    extra = segments * 1 * 6 * (32768 + 65536 + 65536)
    assert size == NUMERIC_PER_CHUNK * (6 * chunks) + extra


def test_fixed_plain_when_wide(gpu):
    """B=1, T=8192, H=96：plain CTA=192 >= 32 => 不分段。"""
    size, cps = _spec()(1, 8192, 96, 1, False)
    assert cps is None
    assert size == NUMERIC_PER_CHUNK * (96 * (8192 // 16))


def test_force_plain_override(gpu, monkeypatch):
    """强制 plain 只改变路径，不改变数值区口径。"""
    auto = _spec()(1, 8192, 6, 1, False)
    monkeypatch.setenv("FLASH_KDA_HCU_SEGMENT", "0")
    forced = _spec()(1, 8192, 6, 1, False)
    assert auto[1] == 32
    assert forced[1] is None
    assert forced[0] == NUMERIC_PER_CHUNK * (6 * 512)


def test_illegal_segment_env_raises(gpu, monkeypatch):
    monkeypatch.setenv("FLASH_KDA_HCU_SEGMENT", "32")
    with pytest.raises(ValueError):
        _spec()(1, 8192, 6, 1, False)


def test_invalid_dims_rejected(gpu):
    spec = _spec()
    for args in ((0, 1024, 6, 1, False), (1, 1024, 0, 1, False),
                 (2, 1024, 6, 2, True), (1, 1024, 6, 0, True)):
        with pytest.raises(ValueError):
            spec(*args)


def test_overflow_guard(gpu):
    with pytest.raises((OverflowError, ValueError, RuntimeError)):
        _spec()(1 << 40, 1 << 20, 1 << 20, 1, False)


def test_feature_bits_layout(gpu):
    """位定义与 native 头一致；四个生产语义全开等于 HCU 要求值 0x0F。"""
    module = _forward_mod()
    assert module.FEATURE_QK_L2NORM == 1
    assert module.FEATURE_GATE == 2
    required = module._features_from_flags(True, True, True, True, False, False)
    assert required == module.HCU_REQUIRED_FEATURES == 0x0F
    assert module._features_from_flags(False, True, True, True, False, False) == 0x0E
    assert module._features_from_flags(True, True, True, True, True, False) == 0x1F
    assert module._features_from_flags(True, True, True, True, False, True) == 0x2F


# ---------------------------------------------------------------------------
# 内部准入：不支持 vs 非法，严格 vs 兼容
# ---------------------------------------------------------------------------
def _strict(x, *, state_dtype="auto", initial_state="auto", **overrides):
    """`_forward` 的关键字封装：``allow_fallback=True``，可逐项覆盖输入。"""
    module = _forward_mod()
    call = dict(
        q=x["q"], k=x["k"], v=x["v"], g=x["g"], beta=x["beta"],
        A_log=x["A_log"], dt_bias=x["dt_bias"],
        scale=cases.SCALE, lower_bound=cases.LOWER_BOUND,
        initial_state=x["state"], output_final_state=True,
        state_dtype=x["state"].dtype, cu_seqlens=x["cu_seqlens"],
        features=module.HCU_REQUIRED_FEATURES, allow_fallback=True,
    )
    call.update(overrides)
    if state_dtype != "auto":
        call["state_dtype"] = state_dtype
    if initial_state != "auto":
        call["initial_state"] = initial_state
    return module._forward(**call)


def test_unsupported_is_not_an_error_but_none(gpu):
    module = _forward_mod()
    x = cases.make_inputs((1, 64, 6), seed=701, state_dtype=torch.float32)
    fallback = module._forward(x["q"], x["k"], x["v"], x["g"], x["beta"],
                               x["A_log"], x["dt_bias"], scale=cases.SCALE,
                               features=0, allow_fallback=True)
    assert fallback[0] is None
    # FP32 q 是"合法但 HCU 不支持"
    fallback = _strict(x, q=x["q"].float())
    assert fallback[0] is None
    # T=0 且非变长是通用非法
    with pytest.raises(ValueError):
        module._forward(x["q"][:, :0], x["k"][:, :0], x["v"][:, :0], x["g"][:, :0],
                        x["beta"][:, :0], x["A_log"], x["dt_bias"], scale=cases.SCALE,
                        features=module.HCU_REQUIRED_FEATURES, allow_fallback=True)


def test_v_shape_mismatch_rejected(gpu):
    module = _forward_mod()
    x = cases.make_inputs((1, 33, 6), seed=702, state_dtype=torch.float32)
    with pytest.raises(ValueError):
        module._forward(x["q"], x["k"], x["v"][:, :1], x["g"], x["beta"],
                        x["A_log"], x["dt_bias"], scale=cases.SCALE,
                        features=module.HCU_REQUIRED_FEATURES)


def test_aux_params_must_share_device(gpu):
    x = cases.make_inputs((1, 128, 6), seed=703, state_dtype=torch.float32)
    with pytest.raises(ValueError):
        _strict(x, A_log=x["A_log"].cpu())


def test_state_dtype_type_errors(gpu):
    x = cases.make_inputs((1, 128, 6), seed=704, state_dtype=torch.float32)
    with pytest.raises(TypeError):
        _strict(x, initial_state=x["state"].to(torch.float16),
                state_dtype=torch.float16)
    with pytest.raises(TypeError):
        _strict(x, initial_state=None, state_dtype=torch.float16)


def test_final_state_without_flag_rejected(gpu):
    module = _forward_mod()
    x = cases.make_inputs((1, 128, 6), seed=705, state_dtype=torch.float32)
    with pytest.raises(ValueError):
        module._forward(x["q"], x["k"], x["v"], x["g"], x["beta"], x["A_log"],
                        x["dt_bias"], scale=cases.SCALE,
                        final_state=torch.empty_like(x["state"]),
                        features=module.HCU_REQUIRED_FEATURES)


def test_chunk_size_is_admission_not_general_error(gpu, monkeypatch):
    """chunk_size=16 是通用非法；64 是"合法但 HCU 不支持"，兼容入口回退 Triton。"""
    from aiter.ops.triton.kimi_delta_attn import chunk_kimi_delta_attn

    x = cases.make_inputs((1, 128, 6), seed=706, state_dtype=torch.float32)
    with pytest.raises(ValueError):
        _strict(x, chunk_size=16)
    assert _strict(x, chunk_size=64)[0] is None
    monkeypatch.setenv("FLASH_KDA_BACKEND", "auto")
    monkeypatch.setenv("FLASH_KDA_HCU_ENABLE", "1")
    out, _ = chunk_kimi_delta_attn(
        x["q"], x["k"], x["v"], x["g"], x["beta"], A_log=x["A_log"],
        dt_bias=x["dt_bias"], scale=cases.SCALE, chunk_size=64,
        use_qk_l2norm_in_kernel=True, use_gate_in_kernel=True,
        use_beta_sigmoid_in_kernel=True, safe_gate=True,
        lower_bound=cases.LOWER_BOUND,
    )
    assert tuple(out.shape) == tuple(x["v"].shape)


def test_strict_rejects_noncontiguous_compat_normalizes(gpu):
    module = _forward_mod()
    x = cases.make_inputs((1, 128, 6), seed=707, state_dtype=torch.float32)
    big = torch.empty((1, 128, 12, 128), dtype=x["q"].dtype, device=x["q"].device)
    q_nc = big[:, :, ::2, :]
    q_nc.copy_(x["q"])
    assert q_nc.shape == x["q"].shape and not q_nc.is_contiguous()
    out, _ = module._forward(
        q_nc, x["k"], x["v"], x["g"], x["beta"], x["A_log"], x["dt_bias"],
        scale=cases.SCALE, lower_bound=cases.LOWER_BOUND,
        initial_state=x["state"], output_final_state=True,
        state_dtype=x["state"].dtype, features=module.HCU_REQUIRED_FEATURES,
        normalize_inputs=True,
    )
    assert out is not None and tuple(out.shape) == tuple(x["v"].shape)
    with pytest.raises(ValueError):
        _strict(x, q=q_nc)


def test_dynamic_segment_env_is_not_cached(gpu, monkeypatch):
    spec = _spec()
    monkeypatch.delenv("FLASH_KDA_HCU_SEGMENT", raising=False)
    auto_cps = spec(1, 8192, 6, 1, False)[1]
    monkeypatch.setenv("FLASH_KDA_HCU_SEGMENT", "0")
    forced_cps = spec(1, 8192, 6, 1, False)[1]
    monkeypatch.delenv("FLASH_KDA_HCU_SEGMENT", raising=False)
    back_cps = spec(1, 8192, 6, 1, False)[1]
    assert auto_cps == 32 and forced_cps is None and back_cps == 32


def test_preallocated_path_returns_same_objects_and_allocates_nothing(gpu):
    module = _forward_mod()
    x = cases.make_inputs((1, 1024, 6), seed=708, state_dtype=torch.float32)
    size, _cps = _spec()(1, 1024, 6, 1, False)
    out = torch.empty_like(x["v"])
    final = torch.empty_like(x["state"])
    workspace = torch.empty(size, dtype=torch.uint8, device=x["q"].device)

    def once():
        return module._forward(
            x["q"], x["k"], x["v"], x["g"], x["beta"], x["A_log"], x["dt_bias"],
            scale=cases.SCALE, lower_bound=cases.LOWER_BOUND,
            initial_state=x["state"], output_final_state=True,
            state_dtype=x["state"].dtype, features=module.HCU_REQUIRED_FEATURES,
            out=out, final_state=final, workspace=workspace,
        )

    got_out, got_final = once()
    torch.cuda.synchronize()
    assert got_out is out and got_final is final
    before = torch.cuda.memory_allocated()
    for _ in range(5):
        once()
    torch.cuda.synchronize()
    assert torch.cuda.memory_allocated() == before


# ---------------------------------------------------------------------------
# 索引 oracle（纯 CPU）
# ---------------------------------------------------------------------------
def test_index_oracle_sequence_info():
    assert cases.chunk_counts([10, 20]) == [1, 2]
    assert cases.sequence_info_from([10, 20]) == [[0, 10, 0], [10, 20, 1]]
    assert cases.sequence_info_from([0, 0, 0]) == [[0, 0, 0], [0, 0, 0], [0, 0, 0]]
    mixed = [0, 3, 17, 0, 28]
    assert cases.chunk_counts(mixed) == [0, 1, 2, 0, 2]
    rows = cases.sequence_info_from(mixed)
    assert [r[2] for r in rows] == [0, 0, 1, 3, 3]   # 空序列不占槽
    assert sum(cases.chunk_counts(mixed)) == 5


def test_index_oracle_head_stride_is_qcap():
    """head stride 是 Qcap（容量），不是实际使用的 chunk 数 Q。"""
    lengths = [17, 16]
    used = sum(cases.chunk_counts(lengths))
    qcap = cases.qcap_for(lengths, 1)          # 容量比实际使用多 1 个 chunk
    assert qcap == used + 1 and qcap > used
    assert cases.p_index(1, qcap, 0, 0) == qcap
    assert cases.p_index(1, used, 0, 0) == used != qcap


def test_index_oracle_slot_ownership_unique():
    lengths = [10, 20, 30, 500, 1000, 2001]
    heads = 3
    qcap = cases.qcap_for(lengths, -1)
    owners = cases.slot_owners(lengths, heads, qcap)
    used = [owner for _slot, owner in owners if owner is not None]
    assert len(owners) == heads * qcap               # 每个 (head, slot) 恰好一次
    assert len(used) == heads * sum(cases.chunk_counts(lengths))
    # 同一个 (seq, local_chunk) 在每个 head 恰好出现一次
    for owner in set(used):
        assert used.count(owner) == heads
    used_p = cases.used_p(lengths, heads, qcap)
    unused_p = cases.unused_p(lengths, heads, qcap)
    assert len(used_p) == len(used)
    assert set(used_p) & set(unused_p) == set()
    assert len(set(used_p) | set(unused_p)) == heads * qcap


def test_beta_address_model_has_no_tail_overflow():
    """2026-10-22 实测越界回归：旧公式缺 bos，会把 beta 位置算到序列之外。"""
    for lengths in ([1, 15], [10, 20, 30, 500, 1000, 2001]):
        total = sum(lengths)
        rows = cases.sequence_info_from(lengths)
        new_positions = []
        old_positions = []
        for bos, length, chunk0 in rows:
            for local in range(cases.chunk_counts([length])[0]):
                valid = min(16, length - local * 16)
                for rel in range(valid):
                    new_positions.append(bos + local * 16 + rel)
                    old_positions.append(chunk0 * 16 + local * 16 + rel)
        assert new_positions, "样例必须至少有一个有效 token"
        assert max(new_positions) < total
        # 旧公式必须在同一批有效 token 上越界，否则这条回归守不住历史 bug。
        assert any(position >= total for position in old_positions)


# ---------------------------------------------------------------------------
# 变长 metadata 与生产 wrapper 的边界
# ---------------------------------------------------------------------------
def _same(left, right):
    """位型相等或 NaN 位置一致的逐元素比较（workspace 字段里含 FP32 位型）。"""
    return torch.equal(left, right) or torch.allclose(
        left.float(), right.float(), rtol=0.0, atol=0.0, equal_nan=True)


def _varlen_k1(lengths, *, heads=6, seed=709):
    from aiter.ops.opus.flash_kda_k1 import flash_kda_k1_varlen_forward

    x = cases.make_inputs((1, sum(lengths), heads), seed=seed,
                          state_dtype=torch.float32, lengths=lengths)
    workspace, meta = flash_kda_k1_varlen_forward(
        x["q"], x["k"], x["g"], x["beta"], x["A_log"],
        x["dt_bias"].reshape(-1),          # native 变长 K1 只接受扁平 [H*128]
        cu_seqlens=x["cu_seqlens"], scale=cases.SCALE, lower_bound=cases.LOWER_BOUND,
    )
    return x, workspace, meta


def test_varlen_k1_rejects_bad_cu(gpu):
    """脏 cu 必须在进 kernel 前被拒：CPU / 浮点 / 2D / 非连续。"""
    from aiter.ops.opus.flash_kda_k1 import flash_kda_k1_varlen_forward

    lengths = [17, 16]
    x = cases.make_inputs((1, sum(lengths), 6), seed=720,
                          state_dtype=torch.float32, lengths=lengths)
    arange = torch.arange(0, 4 * sum(lengths), dtype=torch.int64, device="cuda")
    bad = [
        x["cu_seqlens"].cpu(),
        x["cu_seqlens"].to(torch.float32),
        x["cu_seqlens"].reshape(-1, 1),
        arange[::2][: x["cu_seqlens"].numel()],      # 非连续
    ]
    for cu in bad:
        with pytest.raises((ValueError, TypeError, RuntimeError)):
            flash_kda_k1_varlen_forward(
                x["q"], x["k"], x["g"], x["beta"], x["A_log"],
                x["dt_bias"].reshape(-1), cu_seqlens=cu,
                scale=cases.SCALE, lower_bound=cases.LOWER_BOUND,
            )


def test_varlen_initial_state_shape_uses_sequence_count(gpu):
    """变长初态第一维是 N（序列数），不是物理 B。"""
    from aiter.ops.flash_kda import fwd

    lengths = [17, 16]
    x = cases.make_inputs((1, sum(lengths), 6), seed=721,
                          state_dtype=torch.float32, lengths=lengths)
    out = torch.empty_like(x["v"])
    wrong = torch.zeros((7, 6, 128, 128), dtype=torch.float32, device="cuda")
    with pytest.raises(ValueError):
        fwd(x["q"], x["k"], x["v"], x["g"], x["beta"], cases.SCALE, out,
            x["A_log"], x["dt_bias"], cases.LOWER_BOUND,
            initial_state=wrong, final_state=torch.empty_like(wrong),
            cu_seqlens=x["cu_seqlens"])


def test_varlen_metadata_matches_oracle(gpu):
    lengths = [10, 20, 30, 500, 1000, 2001]
    _x, _ws, meta = _varlen_k1(lengths)
    expected_rows = torch.tensor(cases.sequence_info_from(lengths), dtype=torch.int64)
    assert torch.equal(meta.sequence_info.cpu(), expected_rows)
    expected_chunks = []
    for bos, length, _chunk0 in cases.sequence_info_from(lengths):
        for local in range(cases.chunk_counts([length])[0]):
            expected_chunks.append([bos + local * 16, min(16, length - local * 16)])
    expected_chunks = torch.tensor(expected_chunks, dtype=torch.int64)
    assert torch.equal(meta.chunk_info[: expected_chunks.shape[0]].cpu(), expected_chunks)
    assert int(meta.chunk_capacity_per_head) == cases.qcap_for(lengths, -1)


def test_varlen_metadata_empty_sequences(gpu):
    lengths = [10, 0, 30, 0, 20]
    _x, _ws, meta = _varlen_k1(lengths)
    expected = torch.tensor(cases.sequence_info_from(lengths), dtype=torch.int64)
    assert torch.equal(meta.sequence_info.cpu(), expected)
    # 空序列不占槽：它的 chunk0 与紧随其后的非空序列相同（都不推进 chunk 前缀和）
    rows = expected.tolist()
    assert rows[1][2] == rows[2][2]
    assert rows[3][2] == rows[4][2]


def test_varlen_k2_unused_slots_do_not_affect_results(gpu):
    """未用槽内容不得影响 out/final：换毒值（含清零）后结果必须逐位不变。

    这条守护的是 **K2 的寻址**：只写保护 + 输出仍在合法范围内，并不能排除"读到了空槽或
    别人的槽"——那样换掉未用槽内容就会改变结果。因此这里对同一输入连跑三种未用槽填充
    （毒值 A、毒值 B、全零），要求 out/final 逐位一致，同时保留写保护与尾部哨兵断言。
    算法数值正确性由 `test_fwd.py` 的独立 Triton 对照负责，这里不做阈值比较。
    """
    from aiter.ops.opus.flash_kda_k2 import flash_kda_k2_varlen_forward

    lengths = [17, 19]
    heads = 6
    x, workspace, meta = _varlen_k1(lengths, heads=heads, seed=710)
    qcap = int(meta.chunk_capacity_per_head)
    unused = cases.unused_p(lengths, heads, qcap)
    used = cases.used_p(lengths, heads, qcap)
    assert unused and used, "该样例必须同时存在已用槽与未用槽"
    fields = ("kdqd", "krgt", "inv", "mqk", "beta_sigmoid")
    snapshot = {name: getattr(workspace, name)[used].clone() for name in fields}

    v = x["v"]
    guard = 16
    storage_size = v.numel() + guard * heads * 128

    def run(fill):
        for name, value in fill.items():
            getattr(workspace, name)[unused] = value
        storage = torch.full((storage_size,), 123.0, dtype=v.dtype, device=v.device)
        out = storage[: v.numel()].view_as(v)
        native, final = flash_kda_k2_varlen_forward(
            workspace, v, x["beta"], sequence_info=meta.sequence_info,
            initial_state=x["state"], output_final_state=True, out=out,
            state_dtype=x["state"].dtype,
        )
        torch.cuda.synchronize()
        assert native is out
        assert (storage[v.numel():] == 123).all(), "out 尾部哨兵被写坏（越界写回）"
        for name, value in fill.items():
            assert _same(getattr(workspace, name)[unused],
                         torch.full_like(getattr(workspace, name)[unused], value)), \
                f"未用槽 {name} 被 K2 改写"
        for name in fields:
            assert _same(getattr(workspace, name)[used], snapshot[name]), \
                f"已用槽 {name} 被 K2 改写"
        return out.clone(), final.clone()

    base_out, base_final = run(dict(cases.POISON))
    other = {"kdqd": -3210.0, "krgt": 4096.0, "inv": -1234.0,
             "mqk": 777.0, "beta_sigmoid": -4321.5}
    other_out, other_final = run(other)
    zero_out, zero_final = run({name: 0.0 for name in fields})

    assert torch.isfinite(base_out).all() and torch.isfinite(base_final).all()
    assert _same(base_out, other_out), "换掉未用槽内容后 out 变了：K2 读到了未用槽"
    assert _same(base_final, other_final), "换掉未用槽内容后 final 变了：K2 读到了未用槽"
    assert _same(base_out, zero_out), "未用槽清零后 out 变了：K2 读到了未用槽"
    assert _same(base_final, zero_final), "未用槽清零后 final 变了：K2 读到了未用槽"


def test_varlen_empty_sequence_final_equals_initial(gpu):
    from aiter.ops.opus.flash_kda_k2 import flash_kda_k2_varlen_forward

    lengths = [10, 0, 30]
    heads = 6
    x, workspace, meta = _varlen_k1(lengths, heads=heads, seed=711)
    out, final = flash_kda_k2_varlen_forward(
        workspace, x["v"], x["beta"], sequence_info=meta.sequence_info,
        initial_state=x["state"], output_final_state=True,
        state_dtype=x["state"].dtype,
    )
    torch.cuda.synchronize()
    assert torch.equal(final[1], x["state"][1]), "空序列终态必须逐位等于自己的初态"
    assert torch.isfinite(out).all()


# ---------------------------------------------------------------------------
# 尾块写回边界（强制短分段，避免自动路由成 plain 时漏掉 Replay 尾块）
# ---------------------------------------------------------------------------
@pytest.mark.parametrize("tokens", [33, 65, 129])
def test_segmented_tail_store_guard(gpu, tokens):
    from aiter.ops.opus.flash_kda_k2 import flash_kda_k2_segmented_forward
    from aiter.ops.opus.flash_kda_k1 import flash_kda_k1_forward

    x = cases.make_inputs((1, tokens, 2), seed=cases.case_seed(f"tail{tokens}"),
                          state_dtype=torch.float32)
    workspace, _meta = flash_kda_k1_forward(
        x["q"], x["k"], x["g"], x["beta"], x["A_log"], x["dt_bias"],
        scale=cases.SCALE, lower_bound=cases.LOWER_BOUND,
    )
    # 后缀哨兵与 out 共享 allocation，检测逻辑 tensor 末尾越界。
    storage = torch.full((x["v"].numel() + 16 * 2 * 128,), 123.0,
                         device=x["v"].device, dtype=x["v"].dtype)
    out = storage[: x["v"].numel()].view_as(x["v"])
    native, final = flash_kda_k2_segmented_forward(
        workspace, x["v"], x["beta"], chunks_per_segment=2,
        initial_state=x["state"], output_final_state=True, out=out,
        state_dtype=x["state"].dtype,
    )
    torch.cuda.synchronize()
    assert native is out
    assert (storage[x["v"].numel():] == 123).all(), "尾块写回越界：后缀哨兵被改写"
    assert torch.isfinite(out).all() and torch.isfinite(final).all()


# ---------------------------------------------------------------------------
# graph / 多 stream：独立 buffer 与显式同步
# ---------------------------------------------------------------------------
def _prealloc_call(x, out, final, workspace):
    from aiter.ops.flash_kda import fwd

    fwd(x["q"], x["k"], x["v"], x["g"], x["beta"], cases.SCALE, out,
        x["A_log"], x["dt_bias"], cases.LOWER_BOUND,
        initial_state=x["state"], final_state=final,
        cu_seqlens=x["cu_seqlens"], workspace=workspace)


def test_graph_capture_replay_reflects_new_inputs(gpu):
    """graph 里不能把输入内容捕获成常量：图外改 v，replay 结果必须与非图路径一致。"""
    from aiter.ops.flash_kda import get_workspace_size

    x = cases.make_inputs((1, 65, 6), seed=712, state_dtype=torch.float32)
    size = get_workspace_size(1, 65, 6)
    out = torch.empty_like(x["v"])
    final = torch.empty_like(x["state"])
    workspace = torch.empty(size, dtype=torch.uint8, device=x["q"].device)

    # capture 前完成 JIT 与所有分配（side stream 预热）
    for _ in range(3):
        _prealloc_call(x, out, final, workspace)
    torch.cuda.synchronize()
    side = torch.cuda.Stream()
    side.wait_stream(torch.cuda.current_stream())
    with torch.cuda.stream(side):
        for _ in range(3):
            _prealloc_call(x, out, final, workspace)
    torch.cuda.current_stream().wait_stream(side)
    torch.cuda.synchronize()

    graph = torch.cuda.CUDAGraph()
    with torch.cuda.graph(graph):
        _prealloc_call(x, out, final, workspace)
    torch.cuda.synchronize()

    # 图外修改输入内容后 replay：结果必须跟着变，并与非图路径逐位一致
    x["v"].mul_(0.5)
    graph.replay()
    torch.cuda.synchronize()
    graph_out, graph_final = out.clone(), final.clone()

    plain_out = torch.empty_like(x["v"])
    plain_final = torch.empty_like(x["state"])
    _prealloc_call(x, plain_out, plain_final, workspace)
    torch.cuda.synchronize()
    assert torch.equal(graph_out, plain_out)
    assert torch.equal(graph_final, plain_final)


def test_varlen_graph_replay_rebuilds_metadata_from_cu(gpu):
    """变长 graph：图外改 cu 分区内容，replay 必须按新分区重算，而不是沿用捕获时的分区。

    覆盖的是"cu 内容不被捕获成常量"这一点；它与定长 graph 用例（改 v 内容）互补。
    """
    from aiter.ops.flash_kda import get_workspace_size

    first, second = [17, 16], [1, 32]      # 同 T_total=33、同 N=2，只改分区内容
    total = sum(first)
    x = cases.make_inputs((1, total, 6), seed=730, state_dtype=torch.float32,
                          lengths=first)
    size = get_workspace_size(1, total, 6, sequence_count=len(first), is_varlen=True)
    out = torch.empty_like(x["v"])
    final = torch.empty_like(x["state"])
    workspace = torch.empty(size, dtype=torch.uint8, device=x["q"].device)

    def call():
        from aiter.ops.flash_kda import fwd

        fwd(x["q"], x["k"], x["v"], x["g"], x["beta"], cases.SCALE, out,
            x["A_log"], x["dt_bias"], cases.LOWER_BOUND,
            initial_state=x["state"], final_state=final,
            cu_seqlens=x["cu_seqlens"], workspace=workspace)

    for _ in range(3):
        call()
    torch.cuda.synchronize()
    side = torch.cuda.Stream()
    side.wait_stream(torch.cuda.current_stream())
    with torch.cuda.stream(side):
        for _ in range(3):
            call()
    torch.cuda.current_stream().wait_stream(side)
    torch.cuda.synchronize()

    graph = torch.cuda.CUDAGraph()
    with torch.cuda.graph(graph):
        call()
    torch.cuda.synchronize()
    first_out = out.clone()

    # 图外改 cu 内容（同 shape、同总长），replay 必须反映新分区
    bounds = [0]
    for length in second:
        bounds.append(bounds[-1] + length)
    x["cu_seqlens"].copy_(torch.tensor(bounds, dtype=x["cu_seqlens"].dtype,
                                       device=x["cu_seqlens"].device))
    torch.cuda.synchronize()
    graph.replay()
    torch.cuda.synchronize()
    graph_out, graph_final = out.clone(), final.clone()

    plain_out = torch.empty_like(x["v"])
    plain_final = torch.empty_like(x["state"])
    from aiter.ops.flash_kda import fwd

    fwd(x["q"], x["k"], x["v"], x["g"], x["beta"], cases.SCALE, plain_out,
        x["A_log"], x["dt_bias"], cases.LOWER_BOUND,
        initial_state=x["state"], final_state=plain_final,
        cu_seqlens=x["cu_seqlens"], workspace=workspace)
    torch.cuda.synchronize()

    assert torch.equal(graph_out, plain_out), "replay 没有按新 cu 重新计算"
    assert torch.equal(graph_final, plain_final), "replay 没有按新 cu 重新计算终态"
    assert not torch.equal(graph_out, first_out), "分区内容变了但输出没变（cu 被当成常量？）"


def test_multi_stream_independent_buffers(gpu):
    """两个 stream 各用独立 out/final/workspace 并发，结果必须互不干扰。"""
    from aiter.ops.flash_kda import get_workspace_size

    shapes = [(1, 33, 6), (1, 129, 6)]
    inputs = [cases.make_inputs(shape, seed=713 + index, state_dtype=torch.float32)
              for index, shape in enumerate(shapes)]
    expected = []
    for x, shape in zip(inputs, shapes):
        out = torch.empty_like(x["v"])
        final = torch.empty_like(x["state"])
        size = get_workspace_size(shape[0], shape[1], shape[2])
        _prealloc_call(x, out, final,
                       torch.empty(size, dtype=torch.uint8, device=x["q"].device))
        torch.cuda.synchronize()
        expected.append((out.clone(), final.clone()))

    streams = [torch.cuda.Stream() for _ in inputs]
    results = []
    for index, (x, stream) in enumerate(zip(inputs, streams)):
        batch, tokens, heads = shapes[index]
        size = get_workspace_size(batch, tokens, heads)
        out = torch.empty_like(x["v"])
        final = torch.empty_like(x["state"])
        workspace = torch.empty(size, dtype=torch.uint8, device=x["q"].device)
        results.append((out, final))
        stream.wait_stream(torch.cuda.current_stream())
        with torch.cuda.stream(stream):
            _prealloc_call(x, out, final, workspace)
    for stream in streams:
        torch.cuda.current_stream().wait_stream(stream)
    torch.cuda.synchronize()

    for (out, final), (expected_out, expected_final) in zip(results, expected):
        assert torch.equal(out, expected_out)
        assert torch.equal(final, expected_final)
