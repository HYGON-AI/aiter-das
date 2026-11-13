# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# fused_qk_norm_rope_cache_pts_quant_shuffle 的单 die / 多 die 测试。
# 只依赖已安装的 AITER、Torch 和 Python 标准库。
#
# 在装有 gfx946 perf model 的环境中，于 AITER 仓库根目录执行：
#   单 XCD：GPU_CHIP=sb   python op_tests/gfx946_tests/kv_cache/test_fused_qk_norm_rope_cache_pts_quant_shuffle.py --suite quick --expect-xcds 1
#   双 XCD：GPU_CHIP=sbx2 python op_tests/gfx946_tests/kv_cache/test_fused_qk_norm_rope_cache_pts_quant_shuffle.py --suite route --die-mode linear --chunk 1 --expect-xcds 2
# positions 是一维，宿主把 stride(0) 作为 token 方向的步长。真实设备不设置 GPU_CHIP。
"""Single-die / multi-die checks of the fused QK-norm RoPE cache op."""
import argparse
import ctypes
import ctypes.util
import hashlib
import json
import os
from pathlib import Path

import torch
import aiter  # noqa: F401
from aiter.ops.fused_qk_norm_rope_cache_quant import (
    fused_qk_norm_rope_cache_pts_quant_shuffle,
)

FP8 = torch.float8_e4m3fn
DTYPE = torch.bfloat16
TOKENS, HQ, HK, HV, HEAD = 3, 2, 1, 1, 128
EPS, BLOCK, X, BLOCKS = 1e-6, 16, 16, 2
SLOTS = [3, 16, 19]
POSITIONS = [2, 5, 9]


def topology():
    class Agent(ctypes.Structure):
        _fields_ = [("handle", ctypes.c_uint64)]

    hsa = ctypes.CDLL(ctypes.util.find_library("hsa-runtime64") or "libhsa-runtime64.so.1")
    cb_type = ctypes.CFUNCTYPE(ctypes.c_uint32, Agent, ctypes.c_void_p)
    hsa.hsa_agent_get_info.argtypes = [Agent, ctypes.c_int, ctypes.c_void_p]
    hsa.hsa_iterate_agents.argtypes = [cb_type, ctypes.c_void_p]
    found = []

    @cb_type
    def visit(agent, unused):
        dev = ctypes.c_uint32()
        status = hsa.hsa_agent_get_info(agent, 17, ctypes.byref(dev))
        if status or dev.value != 1:
            return status
        name, count = ctypes.create_string_buffer(64), ctypes.c_uint32()
        status = hsa.hsa_agent_get_info(agent, 0, name)
        if status:
            return status
        status = hsa.hsa_agent_get_info(agent, 0xA111, ctypes.byref(count))
        found.append(dict(name=name.value.decode(), xcds=count.value, status=status))
        return 0

    assert hsa.hsa_init() == 0
    try:
        assert hsa.hsa_iterate_agents(visit, None) == 0
    finally:
        assert hsa.hsa_shut_down() == 0
    return found


def digest(tensor):
    raw = tensor.detach().contiguous().view(torch.uint8).cpu().numpy().tobytes()
    return hashlib.sha256(raw).hexdigest()


def rms_norm(x, weight):
    y = x.float()
    y = y * torch.rsqrt(y.pow(2).mean(-1, keepdim=True) + EPS)
    return weight * y.to(x.dtype)


def rotary(x, cos, sin, neox):
    cos, sin = cos.unsqueeze(-2).to(x.dtype), sin.unsqueeze(-2).to(x.dtype)
    if neox:
        x1, x2 = torch.chunk(x, 2, dim=-1)
        out = torch.cat((x1 * cos - x2 * sin, x2 * cos + x1 * sin), dim=-1)
    else:
        x1, x2 = x[..., ::2], x[..., 1::2]
        out = torch.stack((x1 * cos - x2 * sin, x2 * cos + x1 * sin), dim=-1).flatten(-2)
    return out


def write_shuffle(k, v, k_cache, v_cache, slots):
    hk, head = k.shape[1], k.shape[2]
    for t, slot in enumerate(slots):
        if slot < 0:
            continue
        b, o = slot // BLOCK, slot % BLOCK
        k_cache[b, :, :, o, :] = k[t].reshape(hk, head // X, X)
        v_cache[b, :, o // X, :, o % X] = v[t]


def run_case(stats, neox, quant, slots):
    torch.manual_seed(20261111)
    heads = HQ + HK + HV
    qkv = torch.randn(TOKENS, heads, HEAD, dtype=DTYPE)
    qw = torch.randn(HEAD, dtype=DTYPE)
    kw = torch.randn(HEAD, dtype=DTYPE)
    cos_sin = torch.randn(BLOCKS * BLOCK, HEAD, dtype=DTYPE)
    positions = torch.tensor(POSITIONS, dtype=torch.int64)
    cache_dtype = FP8 if quant else DTYPE
    scale = 1.5 if quant else 1.0
    v_scale = 2.0 if quant else 1.0
    k_cache = torch.zeros(BLOCKS, HK, HEAD // X, BLOCK, X, dtype=cache_dtype)
    v_cache = torch.zeros(BLOCKS, HV, BLOCK // X, HEAD, X, dtype=cache_dtype)
    q, k, v = qkv.reshape(TOKENS, -1).split([HQ * HEAD, HK * HEAD, HV * HEAD], dim=-1)
    q = rms_norm(q.reshape(TOKENS, HQ, HEAD), qw)
    k = rms_norm(k.reshape(TOKENS, HK, HEAD), kw)
    v = v.reshape(TOKENS, HV, HEAD)
    cos, sin = cos_sin[positions].chunk(2, dim=-1)
    q = rotary(q, cos, sin, neox)
    k = rotary(k, cos, sin, neox)
    if quant:
        k = (k.float() / scale).to(FP8)
        v = (v.float() / v_scale).to(FP8)
    # A negative slot skips the cache and the returned K/V; Q is still written.
    for t, slot in enumerate(slots):
        if slot < 0:
            k[t] = 0
            v[t] = 0
    k_ref, v_ref = k_cache.clone(), v_cache.clone()
    write_shuffle(k, v, k_ref, v_ref, slots)
    q_out = torch.empty(TOKENS, HQ, HEAD, dtype=DTYPE, device="cuda")
    k_out = torch.zeros(TOKENS, HK, HEAD, dtype=cache_dtype, device="cuda")
    v_out = torch.zeros(TOKENS, HV, HEAD, dtype=cache_dtype, device="cuda")
    k_dev, v_dev = k_cache.cuda(), v_cache.cuda()
    fused_qk_norm_rope_cache_pts_quant_shuffle(
        qkv.cuda(), qw.cuda(), kw.cuda(), cos_sin.cuda(), positions.cuda(),
        TOKENS, HQ, HK, HV, HEAD, neox, EPS, q_out, k_dev, v_dev,
        torch.tensor(slots, dtype=torch.int64, device="cuda"),
        torch.tensor(scale), torch.tensor(v_scale), k_out, v_out, True, True, BLOCK, X)
    q_tol = (q.float() - q_out.cpu().float()).abs() > (0.05 + 1e-2 * q.float().abs())
    view = (lambda t: t.view(torch.int8).float()) if quant else (lambda t: t.float())
    atol = 1.0 if quant else 0.05
    rtol = 0.0 if quant else 1e-2
    def bad(ref, got):
        delta = (view(got) - view(ref)).abs()
        limit = atol + rtol * view(ref).abs()
        return int((delta > limit).sum())
    missed = dict(q=int(q_tol.sum()), k_cache=bad(k_ref, k_dev.cpu()),
                  v_cache=bad(v_ref, v_dev.cpu()), k_out=bad(k, k_out.cpu()),
                  v_out=bad(v, v_out.cpu()))
    stats.update(missed=missed, q_sha256=digest(q_out), k_sha256=digest(k_dev),
                 grid_x=2, neox=neox, quant=quant)
    # 3 tokens * (2+1+1) heads / 8 warps per 256-thread block, logical warp 32.
    if any(missed.values()):
        raise AssertionError(str(missed))


def expect_reject(fn, text):
    try:
        fn()
    except Exception as exc:
        message = str(exc)
        if text not in message:
            raise AssertionError(message) from exc
        return message.split("\n", 1)[0]
    raise AssertionError("invalid configuration accepted")


def tiny_call(head=HEAD, section_ok=True):
    qkv = torch.zeros(1, HQ + HK + HV, head, dtype=DTYPE, device="cuda")
    w = torch.ones(head, dtype=DTYPE, device="cuda")
    cos = torch.zeros(8, head, dtype=DTYPE, device="cuda")
    pos = torch.zeros(1, dtype=torch.int64, device="cuda")
    cache = torch.zeros(1, 1, head // X, BLOCK, X, dtype=DTYPE, device="cuda")
    q_out = torch.empty(1, HQ, head, dtype=DTYPE, device="cuda")
    slots = torch.zeros(1, dtype=torch.int64, device="cuda")
    fused_qk_norm_rope_cache_pts_quant_shuffle(
        qkv, w, w, cos, pos, 1, HQ, HK, HV, head, True, EPS, q_out, cache, cache,
        slots, torch.tensor(1.0), torch.tensor(1.0), None, None, False, True, BLOCK, X)


def main():
    p = argparse.ArgumentParser()
    p.add_argument("--suite", default="quick", choices=["quick", "pad", "route", "config"])
    p.add_argument("--die-mode", default="auto", choices=["auto", "off", "linear"])
    p.add_argument("--chunk", type=int, default=1)
    p.add_argument("--require-arch", default="gfx946")
    p.add_argument("--expect-xcds", type=int)
    p.add_argument("--json", type=Path)
    args = p.parse_args()
    torch.cuda.init()
    arch = torch.cuda.get_device_properties(0).gcnArchName.split(":")[0]
    assert arch == args.require_arch, (arch, args.require_arch)
    topo = topology()
    if args.expect_xcds:
        assert any(t["xcds"] == args.expect_xcds and t["status"] == 0 for t in topo), topo
    os.environ.pop("GPU_CHIP", None)
    os.environ["AITER_KV_CACHE_DIE_MODE"] = args.die_mode
    os.environ["AITER_KV_CACHE_DIE_CHUNK"] = str(args.chunk)
    os.environ["AITER_KV_CACHE_LOG_LAUNCH"] = "1"
    header = dict(op="fused_qk_norm_rope_cache_pts_quant_shuffle", arch=arch,
                  topology=topo, suite=args.suite, mode=args.die_mode, chunk=args.chunk)
    print(json.dumps(header), flush=True)
    catalog = {
        "quick": [
            ("bf16_neox", True, False, SLOTS),
            ("bf16_gptj", False, False, SLOTS),
            ("fp8_neox", True, True, SLOTS),
        ],
        "pad": [("bf16_negative_slot", True, False, [3, -1, 19])],
        "route": [("bf16_neox", True, False, SLOTS)],
    }
    failed = 0
    records = []
    for name, neox, quant, slots in catalog.get(args.suite, []):
        entry = dict(id=name, neox=neox, quant=quant, slots=slots)
        try:
            run_case(entry, neox, quant, slots)
            entry["status"] = "PASS"
        except Exception as exc:
            entry["status"] = "FAIL"
            entry["error"] = str(exc).split("\n", 1)[0]
            failed += 1
        records.append(entry)
        print(json.dumps(entry), flush=True)
    if args.suite == "config":
        multi = arch == "gfx946" and any(t["xcds"] >= 2 and t["status"] == 0 for t in topo)
        checks = [("bad_mode", "nope", None, "AITER_KV_CACHE_DIE_MODE must be auto, off or linear"),
                  ("bad_head", None, None, "head_size == 64")]
        if multi:
            checks.append(("zero_chunk", "linear", "0", "AITER_KV_CACHE_DIE_CHUNK must be positive"))
        else:
            text = ("at least 2 reported XCDs" if arch == "gfx946"
                    else "requires a build targeting gfx946")
            checks.append(("linear_rejected", "linear", "1", text))
        for name, mode, chunk, text in checks:
            if mode:
                os.environ["AITER_KV_CACHE_DIE_MODE"] = mode
            if chunk:
                os.environ["AITER_KV_CACHE_DIE_CHUNK"] = chunk
            entry = dict(id=name)
            try:
                call = (lambda: tiny_call(head=32)) if name == "bad_head" else tiny_call
                if name == "bad_head":
                    os.environ["AITER_KV_CACHE_DIE_MODE"] = "auto"
                entry["error"] = expect_reject(call, text)
                entry["status"] = "PASS"
            except Exception as exc:
                entry["status"] = "FAIL"
                entry["error"] = str(exc).split("\n", 1)[0]
                failed += 1
            records.append(entry)
            print(json.dumps(entry), flush=True)
    summary = dict(passed=len(records) - failed, failed=failed)
    print(json.dumps(dict(header, **summary)), flush=True)
    if args.json:
        args.json.write_text(json.dumps(dict(header, cases=records, **summary), indent=2))
    if failed:
        raise SystemExit(1)


if __name__ == "__main__":
    main()
