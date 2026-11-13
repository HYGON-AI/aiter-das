# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Small public-interface checks with CPU references (no timing loop).

Usage from the repository root:
  python op_tests/gfx946_tests/fla/test_fla.py --suite build --rebuild
  GPU_CHIP=sb python op_tests/gfx946_tests/fla/test_fla.py --expect-xcds 1
  GPU_CHIP=sbx2 python op_tests/gfx946_tests/fla/test_fla.py --expect-xcds 2
  python op_tests/gfx946_tests/fla/test_fla.py --op vllm_gating --require-arch gfx938
See README.md for environment, full coverage and dispatch acceptance.
"""
import argparse
import ctypes
import ctypes.util
import hashlib
import inspect
import json
import os
from pathlib import Path
import sys
import traceback

ROOT = Path(__file__).resolve().parents[3]
OPS = ("sglang_chunk", "vllm_chunk", "chunk_o", "packed_decode", "sglang_gating", "vllm_gating")


def topology():
    class Agent(ctypes.Structure):
        _fields_ = [("handle", ctypes.c_uint64)]
    hsa = ctypes.CDLL(ctypes.util.find_library("hsa-runtime64") or "libhsa-runtime64.so.1")
    callback = ctypes.CFUNCTYPE(ctypes.c_uint32, Agent, ctypes.c_void_p)
    hsa.hsa_agent_get_info.argtypes = [Agent, ctypes.c_int, ctypes.c_void_p]
    hsa.hsa_iterate_agents.argtypes = [callback, ctypes.c_void_p]
    found = []

    @callback
    def visit(agent, _):
        kind, count = ctypes.c_uint32(), ctypes.c_uint32()
        status = hsa.hsa_agent_get_info(agent, 17, ctypes.byref(kind))
        if status or kind.value != 1:
            return status
        name = ctypes.create_string_buffer(64)
        ns = hsa.hsa_agent_get_info(agent, 0, name)
        xs = hsa.hsa_agent_get_info(agent, 0xA111, ctypes.byref(count))
        found.append(dict(name=name.value.decode(), xcds=count.value, name_status=ns, xcd_status=xs))
        return 0
    assert hsa.hsa_init() == 0
    try:
        assert hsa.hsa_iterate_agents(visit, None) == 0
    finally:
        hsa.hsa_shut_down()
    return found


def cases(suite):
    result = []
    for op in OPS:
        configs = [dict(tag="route", dtype="float16", lengths=[1, 1])]
        if suite == "full":
            configs += [dict(tag="boundary", dtype="bfloat16", lengths=[63, 65], packed=True),
                        dict(tag="full_chunk", dtype="float16", lengths=[64]),
                        dict(tag="optional", dtype="bfloat16", lengths=[1, 1], optional=True),
                        dict(tag="branches", dtype="float16", lengths=[3, 2], packed=True, branches=True)]
            if op == "packed_decode":
                configs = [dict(tag="route", dtype="float16", lengths=[1, 1]),
                           dict(tag="state_bf16", dtype="bfloat16", lengths=[1, 1], optional=True),
                           dict(tag="state_fp16", dtype="float16", lengths=[1, 1], state_dtype="float16"),
                           dict(tag="padding", dtype="float16", lengths=[1, 1], branches=True)]
            elif op in ("sglang_gating", "vllm_gating"):
                configs[1]["lengths"] = [1, 3]
                configs[2]["lengths"] = [2]
                if op == "sglang_gating":
                    configs.append(dict(tag="replay", dtype="bfloat16", lengths=[2, 1], packed=True, branches=True, replay=True))
                    configs.append(dict(tag="state_fp16", dtype="float16", lengths=[1, 1], state_dtype="float16"))
                else:
                    configs.append(dict(tag="padding", dtype="float16", lengths=[1, 1], padding=True))
            elif op == "vllm_chunk":
                configs += [dict(tag="no_values", dtype="float16", lengths=[1], omit_value=True),
                            dict(tag="zero_initial_no_final", dtype="float16", lengths=[1], omit_final=True, zero_initial=True)]
        for c in configs:
            c.update(op=op, name=f"{op}_{c['tag']}")
            result.append(c)
    return result


def rand(shape, dtype, scale=0.1):
    return (torch.randn(shape, generator=GEN) * scale).to(dtype)


def check(name, actual, expected, records, exact=False):
    actual = actual.detach().cpu()
    assert actual.shape == expected.shape, (name, actual.shape, expected.shape)
    assert actual.dtype == expected.dtype, (name, actual.dtype, expected.dtype)
    # Low precision products round at matrix boundaries. These fixed tolerances
    # cover that rounding; every element must pass, including values near zero.
    atol, rtol = (0.0, 0.0) if exact else ((0.002, 0.02) if actual.dtype == torch.bfloat16 else (0.0002, 0.005))
    diff = (actual.float() - expected.float()).abs()
    records.append(dict(name=name, max_abs=float(diff.max()) if diff.numel() else 0.0,
                        atol=atol, rtol=rtol,
                        sha256=hashlib.sha256(actual.contiguous().view(torch.uint8).numpy().tobytes()).hexdigest()))
    torch.testing.assert_close(actual, expected, atol=atol, rtol=rtol, equal_nan=False,
                               msg=lambda detail: f"{name}\n{detail}")


def dut(name, fn):
    torch.cuda.synchronize()
    print("DUT_BEGIN", name, flush=True)
    if os.environ.get("AITER_FLA_TEST_SPLIT_LOG") == "1":
        print("DUT_BEGIN", name, file=sys.stderr, flush=True)
    result = fn()
    torch.cuda.synchronize()
    print("DUT_END", name, flush=True)
    if os.environ.get("AITER_FLA_TEST_SPLIT_LOG") == "1":
        print("DUT_END", name, file=sys.stderr, flush=True)
    return result


def metadata(lengths, dtype):
    cu = torch.tensor([0] + list(__import__("itertools").accumulate(lengths)), dtype=dtype)
    counts = [(n + 63) // 64 for n in lengths]
    ci = torch.tensor([[i, j] for i, n in enumerate(counts) for j in range(n)], dtype=dtype)
    offsets = torch.tensor([sum(counts[:i]) for i in range(len(counts))], dtype=torch.int64)
    return cu, ci, offsets


def chunk_case(c, records):
    dtype = getattr(torch, c["dtype"])
    lengths = c["lengths"]
    packed = c.get("packed", False)
    B, T, H, K, V = (1 if packed else len(lengths)), (sum(lengths) if packed else lengths[0]), 1, 128, 128
    optional = c.get("optional", False)
    save_value = not c.get("omit_value", optional)
    output_final = not c.get("omit_final", optional)
    branch = c.get("branches", False)
    H, Hg = (2 if branch else 1), 1
    k = rand((B, T, Hg, K), dtype)
    w, u = (rand((B, T, H, K), dtype) for _ in range(2))
    g = None if optional else -torch.arange(1, T + 1).remainder(64).float().reshape(1, T, 1).expand(B, T, H).contiguous() * 0.002
    gk = rand((B, T, H, K), torch.float32, 0.01) if branch else None
    exp2 = branch
    sg = c["op"] == "sglang_chunk"
    state_dtype = torch.bfloat16 if sg and optional else torch.float32
    storage = rand((len(lengths) * 2 + 2, H, V, K), state_dtype)
    pool = storage[::2]
    ids = torch.arange(len(lengths), dtype=torch.int32)
    if sg and optional:
        ids[-1] = -1
    initial = None if (not sg and (optional or c.get("zero_initial"))) else pool
    cu, ci, offsets = metadata(lengths, torch.int64 if branch else torch.int32)
    NT = len(ci) if packed else (T + 63) // 64
    hs = torch.empty((B, NT, H, V, K), dtype=dtype)
    vn = torch.empty_like(u)
    final = pool.clone().float()
    kf = k.reshape(-1, Hg, K)
    wf, uf = (x.reshape(-1, H, K) for x in (w, u))
    # Safe exponentiation applies to SGLang gate differences, not state decay.
    exp = (lambda x: torch.where(x <= 0, x.exp(), torch.zeros_like(x))) if sg else (torch.exp2 if exp2 else torch.exp)
    state_exp = torch.exp if sg else exp
    for n, length in enumerate(lengths):
        bos = sum(lengths[:n])
        slot = int(ids[n])
        state = pool[slot].float().clone() if initial is not None and slot >= 0 else torch.zeros(H, V, K)
        for ch, start in enumerate(range(0, length, 64)):
            sl = slice(bos + start, bos + min(start + 64, length))
            hi = int(offsets[n]) + ch if packed else n * NT + ch
            hs.view(-1, H, V, K)[hi] = state.to(dtype)
            for head in range(H):
                residual = uf[sl, head].float() - wf[sl, head].float() @ state[head].to(dtype).float().T
                vn.view(-1, H, V)[sl, head] = residual.to(dtype)
                if g is not None:
                    gate = g.reshape(-1, H)[sl, head]
                    residual *= exp(gate[-1] - gate)[:, None]
                    state[head] *= state_exp(gate[-1])
                if gk is not None:
                    state[head] *= state_exp(gk.reshape(-1, H, K)[sl, head][-1])[None, :]
                state[head] += residual.to(dtype).float().T @ kf[sl, head // (H // Hg)].float()
        if slot >= 0:
            final[slot] = state
    gs = storage.cuda()
    gp = gs[::2]
    kw = dict(g=None if g is None else g.cuda(), gk=None if gk is None else gk.cuda(),
              initial_state=gp if initial is not None else None,
              initial_state_indices=ids.cuda() if initial is not None else None,
              output_final_state=output_final, save_new_value=save_value, use_exp2=exp2)
    if packed:
        kw.update(cu_seqlens=cu.cuda(), chunk_indices=ci.cuda(), chunk_offsets=offsets.cuda())
    fn = getattr(fla, "chunk_gated_delta_rule_fwd_" + ("sglang" if sg else "vllm") + "_hip_blockdim64")
    inputs = [x.cuda() for x in (k, w, u)]
    result = dut(c["name"], lambda: fn(*inputs, **kw))
    assert isinstance(result, tuple) and len(result) == (2 if sg else 3)
    check("h", result[0], hs, records)
    if not save_value:
        assert result[1] is None
    else:
        check("v_new", result[1], vn, records)
    if sg:
        expected = storage.clone()
        for slot in ids.tolist():
            if slot >= 0:
                expected[slot * 2] = final[slot].to(state_dtype)
        check("pool_and_guards", gs, expected, records)
        check("unselected", gs[1::2], storage[1::2], records, True)
        check("unused_slot", gp[-1], pool[-1], records, True)
    else:
        check("input_pool_unchanged", gs, storage, records, True)
        if not output_final:
            assert result[2] is None
        else:
            assert result[2].data_ptr() != gp.data_ptr()
            for slot in ids.tolist():
                check(f"final_{slot}", result[2][slot], final[slot], records)


def output_case(c, records):
    dtype = getattr(torch, c["dtype"])
    lengths, packed = c["lengths"], c.get("packed", False)
    B, T, H, D = (1 if packed else len(lengths)), (sum(lengths) if packed else lengths[0]), 1, 128
    q, k, v = (rand((B, T, H, D), dtype) for _ in range(3))
    cu, ci, offsets = metadata(lengths, torch.int32)
    NT = len(ci) if packed else (T + 63) // 64
    h = rand((B, NT, H, D, D), dtype)
    g = None if c.get("optional") else -torch.arange(T).reshape(1, T, 1).expand(B, T, H).float().contiguous() * 0.002
    gamma = torch.tensor([-0.01]) if c.get("branches") else None
    exp2 = c.get("branches", False)
    exp = torch.exp2 if exp2 else torch.exp
    expected = torch.empty_like(v)
    scale = 0.125
    for n, length in enumerate(lengths):
        bos = sum(lengths[:n])
        for ch, start in enumerate(range(0, length, 64)):
            sl = slice(bos + start, bos + min(start + 64, length))
            qq, kk, vv = [x.view(-1, D)[sl].float() for x in (q, k, v)]
            hh = h.view(-1, D, D)[int(offsets[n]) + ch if packed else n * NT + ch].float()
            t = torch.arange(len(qq)).float()
            gates = torch.zeros_like(t) if g is None else g.reshape(-1)[sl]
            if gamma is not None:
                gates = gates + (t + 1) * gamma[0]
            scores = (qq @ kk.T) * exp(gates[:, None] - gates[None, :])
            scores = torch.tril(scores) * scale
            out = (qq @ hh.T) * exp(gates)[:, None] * scale + scores.to(dtype).float() @ vv
            expected.view(-1, D)[sl] = out.to(dtype)
    inputs = [x.cuda() for x in (q, k, v, h)]
    kw = dict(g=None if g is None else g.cuda(), g_gamma=None if gamma is None else gamma.cuda(), scale=scale, use_exp2=exp2)
    if packed:
        kw.update(cu_seqlens=cu.cuda(), chunk_indices=ci.cuda())
    result = dut(c["name"], lambda: fla.chunk_fwd_o_vllm_hip_blockdim64(*inputs, **kw))
    check("out", result, expected, records)


def recurrent_case(c, records):
    dtype = getattr(torch, c["dtype"])
    lengths = c["lengths"]
    packed = c.get("packed", False)
    B, T, H, HV, K, V = (1 if packed else len(lengths)), (sum(lengths) if packed else lengths[0]), 1, 2, 128, 128
    sg, decode = c["op"] == "sglang_gating", c["op"] == "packed_decode"
    branch, optional = c.get("branches", False), c.get("optional", False)
    kda, norm = branch and not decode, optional or branch
    replay = c.get("replay", False)
    q, k = (rand((B, T, H, K), dtype) for _ in range(2))
    v = rand((B, T, HV, V), dtype)
    a = rand((B, T, HV, K) if kda else (B, T, HV), dtype)
    b, al = rand((B, T, HV), dtype), rand((HV,), torch.float32)
    dt = rand((HV, K) if kda else (HV,), dtype)
    state_dtype = torch.bfloat16 if optional and (sg or decode) else torch.float32
    if c.get("state_dtype"):
        state_dtype = getattr(torch, c["state_dtype"])
    slots = sum(lengths) + 2
    storage = rand((slots * 2, HV, V, K), state_dtype)
    pool = storage[::2]
    ids = torch.arange(len(lengths), dtype=torch.int32)
    if optional and sg or branch and decode:
        ids[-1] = -1
    cu, _, _ = metadata(lengths, torch.int32)
    idx2 = torch.full((len(lengths), max(lengths)), -1, dtype=torch.int32)
    for n, length in enumerate(lengths):
        idx2[n, :length] = torch.arange(sum(lengths[:n]), sum(lengths[:n + 1]))
    if c.get("padding"):
        idx2[-1, 0] = -1
    accepted = torch.tensor([min(2, length) for length in lengths], dtype=torch.int32)
    cache = torch.full((slots, max(lengths), HV, V, K), 0.375, dtype=state_dtype)
    cache_ids = ids.clone()
    parents = torch.tensor([[max(0, t - 2) for t in range(max(lengths))] for _ in lengths], dtype=torch.int32)
    output = torch.empty_like(v)
    expected_storage, expected_cache = storage.clone(), cache.clone()
    replay_v = torch.full((slots, HV, max(lengths), V), 0.375, dtype=dtype)
    replay_k = torch.full((slots, H, max(lengths), K), 0.375, dtype=dtype)
    replay_g = torch.full((slots, HV, max(lengths), K), 0.375)
    replay_b = torch.full((slots, HV, max(lengths)), 0.375)
    expected_replay = [x.clone() for x in (replay_v, replay_k, replay_g, replay_b)]
    final_tokens = torch.empty((sum(lengths), HV, V, K))
    for n, length in enumerate(lengths):
        bos = sum(lengths[:n])
        slot = int(ids[n]) if sg or decode else int(idx2[n, int(accepted[n]) - 1] if branch else idx2[n, 0])
        if not sg and not decode and slot < 0:
            continue
        state = pool[slot].float().clone() if slot >= 0 else torch.zeros(HV, V, K)
        for t in range(length):
            token = bos + t
            if sg and branch and t > 0 and int(parents[n, t]) != t - 1:
                state = expected_cache[int(cache_ids[n]), int(parents[n, t])].float().clone()
            for hv in range(HV):
                qq, kk = q.view(-1, H, K)[token, 0].float(), k.view(-1, H, K)[token, 0].float()
                if norm:
                    qq = qq * torch.rsqrt(qq.square().sum() + 1e-6)
                    kk = kk * torch.rsqrt(kk.square().sum() + 1e-6)
                aa = a.reshape(-1, HV, K)[token, hv].float() if kda else a.reshape(-1, HV)[token, hv].float()
                log_gate = -al[hv].exp() * torch.nn.functional.softplus(aa + dt[hv].float())
                if replay:
                    log_gate = -2.0 * (al[hv].exp() * (aa + dt[hv].float())).sigmoid()
                gate = log_gate.exp()
                state[hv] *= gate
                beta = b.reshape(-1, HV)[token, hv].float().sigmoid()
                if replay:
                    beta *= 0.75
                vv = v.view(-1, HV, V)[token, hv].float()
                if replay and slot >= 0:
                    expected_replay[0][slot, hv, t] = vv.to(dtype)
                    expected_replay[1][slot, 0, t] = k.view(-1, H, K)[token, 0]
                    expected_replay[2][slot, hv, t] = log_gate
                    expected_replay[3][slot, hv, t] = beta
                state[hv] += ((vv - state[hv] @ kk) * beta)[:, None] * kk[None, :]
                output.view(-1, HV, V)[token, hv] = (state[hv] @ qq * 0.125).to(dtype)
            if decode and slot < 0:
                output.view(-1, HV, V)[token].zero_()
            if sg:
                if branch and slot >= 0:
                    expected_cache[int(cache_ids[n]), t] = state.to(state_dtype)
            elif not decode:
                final_tokens[token] = state
                if not optional:
                    expected_storage[int(idx2[n, t]) * 2] = state.to(state_dtype)
        if (sg and not branch or decode) and slot >= 0:
            expected_storage[slot * 2] = state.to(state_dtype)
    gs, gc = storage.cuda(), cache.cuda()
    gp = gs[::2]
    qg, kg, vg, ag, bg, alg, dtg = [x.cuda() for x in (q, k, v, a, b, al, dt)]
    if decode:
        mixed = torch.cat((q.reshape(B, -1), k.reshape(B, -1), v.reshape(B, -1)), dim=1).cuda()
        out = torch.full_like(v, 0.375).cuda()
        result = dut(c["name"], lambda: fla.aiter_fused_recurrent_gated_delta_rule_packed_decode(mixed, ag.reshape(B, HV), bg.reshape(B, HV), alg, dtg, 0.125, gp, out, ids.cuda(), norm))
        assert len(result) == 2 and result[0].data_ptr() == out.data_ptr() and result[1].data_ptr() == gp.data_ptr()
        actual = result[0]
    elif sg:
        kw = dict(scale=0.125, use_qk_l2norm_in_kernel=norm, is_kda=kda, disable_state_update=branch)
        if packed:
            kw["cu_seqlens"] = cu.cuda()
        if branch:
            kw.update(intermediate_states_buffer=gc, intermediate_state_indices=cache_ids.cuda(), cache_steps=max(lengths), retrieve_parent_token=parents.cuda())
        if replay:
            replay_buffers = [x.cuda() for x in (replay_v, replay_k, replay_g, replay_b)]
            kw.update(lower_bound=-2.0, beta_scale=0.75, cache_replayssm_inputs=True,
                      **dict(zip(("replayssm_rawv", "replayssm_rawk", "replayssm_g", "replayssm_beta"), replay_buffers)))
        actual = dut(c["name"], lambda: fla.sglang_fused_sigmoid_gating_delta_rule_update(alg, ag, dtg, 1., 20., qg, kg, vg, bg, gp, ids.cuda(), **kw))
        if branch:
            check("tree_cache", gc, expected_cache, records)
        if replay:
            for i, (actual_replay, ref) in enumerate(zip(replay_buffers, expected_replay)):
                check(f"replay_{i}", actual_replay, ref, records, i < 2)
    else:
        kw = dict(scale=0.125, initial_state=gp, inplace_final_state=not optional,
                  ssm_state_indices=idx2.cuda(), use_qk_l2norm_in_kernel=norm, is_kda=kda)
        if packed:
            kw["cu_seqlens"] = cu.cuda()
        if branch:
            kw["num_accepted_tokens"] = accepted.cuda()
        result = dut(c["name"], lambda: fla.vllm_fused_sigmoid_gating_delta_rule_update(alg, ag, bg, dtg, qg, kg, vg, **kw))
        assert isinstance(result, tuple) and len(result) == 2
        actual = result[0]
        if optional:
            assert result[1].data_ptr() != gp.data_ptr()
            # Out-of-place native output is T-sized; use packed input for B>1.
            check("final_tokens", result[1], final_tokens, records)
        else:
            assert result[1].data_ptr() == gp.data_ptr()
    if c.get("padding"):
        assert actual.shape == output.shape and actual.dtype == output.dtype
        check("valid_out", actual[0], output[0], records)
    else:
        check("out", actual, output, records)
    frozen = (sg and branch) or (not sg and not decode and optional)
    check("pool", gs, expected_storage, records, frozen)
    if frozen:
        written = set()
    elif sg or decode:
        written = {s for s in ids.tolist() if s >= 0}
    else:
        written = {s for row in idx2.tolist() for s in row if s >= 0}
    untouched = [i for i in range(slots) if i not in written]
    check("unselected_slots", gp.detach().cpu()[untouched], pool[untouched], records, True)
    check("storage_guards", gs[1::2], storage[1::2], records, True)
    check("unused_slot", gp[-1], pool[-1], records, True)


def rejection_checks(op):
    q = torch.zeros((1, 1, 1, 128), dtype=torch.float16, device="cuda")
    state = torch.zeros((1, 1, 128, 128), device="cuda")
    ids = torch.zeros(1, dtype=torch.int32, device="cuda")
    gate = torch.zeros((1, 1, 1), dtype=torch.float16, device="cuda")
    al = torch.zeros(1, device="cuda")
    dt = torch.zeros(1, dtype=torch.float16, device="cuda")
    tests = []
    if op.endswith("chunk"):
        fn = getattr(fla, "chunk_gated_delta_rule_fwd_" + op.split("_")[0] + "_hip_blockdim64")
        kw = dict(initial_state=state, initial_state_indices=ids)
        tests += [("chunk_size", "chunk_size", lambda: fn(q, q, q, chunk_size=32, **kw)),
                  ("gate_dtype", "float32", lambda: fn(q, q, q, g=gate, **kw)),
                  ("state_dtype", "float32", lambda: fn(q, q, q, initial_state=state.half(), initial_state_indices=ids))]
        if op == "sglang_chunk":
            tests.append(("layout", "transpose_state_layout", lambda: fn(q, q, q, transpose_state_layout=False, **kw)))
    elif op == "chunk_o":
        h = state.to(torch.float16).unsqueeze(1)
        tests += [("chunk_size", "chunk_size", lambda: fla.chunk_fwd_o_vllm_hip_blockdim64(q, q, q, h, chunk_size=32)),
                  ("layout", "transpose_state_layout", lambda: fla.chunk_fwd_o_vllm_hip_blockdim64(q, q, q, h, transpose_state_layout=False))]
    elif op == "packed_decode":
        mixed = torch.zeros((1, 384), dtype=torch.float16, device="cuda")
        tests.append(("out_dtype", "out dtype", lambda: fla.aiter_fused_recurrent_gated_delta_rule_packed_decode(mixed, gate.view(1, 1), gate.view(1, 1), al, dt, 1., state, q.float(), ids)))
    elif op == "sglang_gating":
        tests.append(("softplus_beta", "positive", lambda: fla.sglang_fused_sigmoid_gating_delta_rule_update(al, gate, dt, 0., 20., q, q, q, gate, state, ids)))
    else:
        tests.append(("required_state", "initial_state", lambda: fla.vllm_fused_sigmoid_gating_delta_rule_update(al, gate, gate, dt, q, q, q)))
    passed = []
    for name, message, invoke in tests:
        try:
            invoke()
        except (RuntimeError, ValueError) as exc:
            assert message in str(exc), (name, str(exc))
            passed.append(name)
        else:
            raise AssertionError(f"{op}:{name} did not reject")
    return passed


def main(default_op=None):
    ap = argparse.ArgumentParser(description=__doc__)
    ap.add_argument("--op", choices=OPS, default=default_op)
    ap.add_argument("--suite", choices=("quick", "full", "build"), default="quick")
    ap.add_argument("--case")
    ap.add_argument("--list", action="store_true")
    ap.add_argument("--rebuild", action="store_true")
    ap.add_argument("--refresh", action="store_true", help="relink module and rebuild changed sources/headers using compiler dependencies")
    ap.add_argument("--require-arch", default="gfx946")
    ap.add_argument("--expect-xcds", type=int)
    ap.add_argument("--die-mode", choices=("auto", "off", "linear"), default="auto")
    ap.add_argument("--chunk", type=int, default=1)
    ap.add_argument("--json", type=Path, default=Path("fla_result.json"))
    args = ap.parse_args()
    selected = [c for c in cases(args.suite) if (not args.op or c["op"] == args.op) and (not args.case or c["name"] == args.case)]
    if args.list:
        print(json.dumps(selected, indent=2))
        return
    assert selected or args.suite == "build", "No cases selected"
    os.environ.update(AITER_FLA_DIE_MODE=args.die_mode, AITER_FLA_DIE_CHUNK=str(args.chunk), AITER_FLA_LOG_LAUNCH="1")
    sys.path.insert(0, str(ROOT))
    global torch, fla, GEN
    import torch
    import aiter
    import aiter.ops.fla as fla
    from aiter.jit import core
    torch.set_num_threads(1)
    GEN = torch.Generator().manual_seed(946)
    assert Path(aiter.__file__).resolve().parent == ROOT / "aiter", aiter.__file__
    result = dict(status="RUNNING", args=vars(args) | dict(json=str(args.json)), aiter=aiter.__file__, torch=torch.__version__, hip=torch.version.hip,
                  test_sha256=hashlib.sha256(Path(__file__).read_bytes()).hexdigest(), cases=[])
    def save():
        args.json.parent.mkdir(parents=True, exist_ok=True)
        args.json.write_text(json.dumps(result, indent=2) + "\n", encoding="utf-8")
    save()
    try:
        name = "module_cpp_api"
        if args.rebuild or args.refresh:
            core.AITER_REBUILD = 1 if args.rebuild else 2
            build = core.get_args_of_build(name) | dict(md_name=name)
            core.build_module(**{k: v for k, v in build.items() if k in inspect.signature(core.build_module).parameters})
            core.AITER_REBUILD = 0
            core.rebuilded_list.append(name)
        module = core.get_module(name)
        p = Path(module.__file__).resolve()
        result["module"] = dict(path=str(p), sha256=hashlib.sha256(p.read_bytes()).hexdigest())
        sources = list((ROOT / "csrc/fla").rglob("*.h")) + list((ROOT / "csrc/fla").rglob("*.cu"))
        sources += [ROOT / s for s in ("aiter/ops/fla.py", "aiter/jit/core.py", "aiter/jit/optCompilerConfig.json", "csrc/include/hip_kernel_launch.h", "csrc/pybind/cpp_api_pybind.cu", "csrc/fla/fla_api.cpp")]
        result["sources"] = {str(p.relative_to(ROOT)): hashlib.sha256(p.read_bytes()).hexdigest() for p in sources}
        if args.suite != "build":
            props = torch.cuda.get_device_properties(0)
            arch = props.gcnArchName.split(":")[0]
            assert arch == args.require_arch, arch
            agents = topology() if arch == "gfx946" else []
            if args.expect_xcds is not None:
                assert len(agents) == 1 and agents[0]["xcd_status"] == 0 and agents[0]["xcds"] == args.expect_xcds, agents
            result.update(arch=arch, topology=agents, device=str(props), gpu_chip=os.environ.get("GPU_CHIP"))
            print("ENV", json.dumps({k: v for k, v in result.items() if k != "sources"}), flush=True)
            for c in selected:
                GEN.manual_seed(946 + sum(c["name"].encode()))
                # The native non-inplace vLLM allocation is T-sized.
                if c["op"] == "vllm_gating" and c.get("optional"):
                    c["packed"] = True
                records = []
                item = dict(case=c, status="RUNNING", checks=records)
                result["cases"].append(item)
                save()
                if c["op"].endswith("chunk"):
                    chunk_case(c, records)
                elif c["op"] == "chunk_o":
                    output_case(c, records)
                else:
                    recurrent_case(c, records)
                item["status"] = "PASS"
                print("PASS", c["name"], flush=True)
                save()
            assert len(result["cases"]) == len(selected) and all(x["status"] == "PASS" for x in result["cases"])
            if args.suite == "full":
                result["rejections"] = {op: rejection_checks(op) for op in OPS if not args.op or op == args.op}
        result["status"] = "PASS"
    except BaseException:
        result["status"] = "FAIL"
        result["error"] = traceback.format_exc()
        raise
    finally:
        save()


if __name__ == "__main__":
    main()
