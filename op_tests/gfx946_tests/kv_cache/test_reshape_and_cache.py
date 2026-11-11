# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# reshape_and_cache 的单 die / 多 die 测试。只依赖已安装的 AITER、Torch 和
# Python 标准库。fp8 用例核对的是当前分发实际写入的 bf16 低 8 位，不是
# torch.float8 的 scale 量化结果。
#
# 在装有 gfx946 perf model 的环境中，于 AITER 仓库根目录执行：
#   export GPU_ARCHS=gfx946
#   unset AITER_JIT_DIR PYTHONPATH AITER_REBUILD
# 单 XCD：GPU_CHIP=sb  python op_tests/gfx946_tests/kv_cache/test_reshape_and_cache.py --suite quick --expect-xcds 1
# 双 XCD：GPU_CHIP=sbx2 python op_tests/gfx946_tests/kv_cache/test_reshape_and_cache.py --suite quick --expect-xcds 2
#         GPU_CHIP=sbx2 python op_tests/gfx946_tests/kv_cache/test_reshape_and_cache.py --suite route --die-mode linear --chunk 2 --expect-xcds 2
# 真实设备使用自身拓扑，不设置 GPU_CHIP。模型选择必须在 Python/HIP 初始化之前完成。
"""Single-die / multi-die checks of aiter.reshape_and_cache."""
import argparse
import ctypes
import ctypes.util
import hashlib
import json
import os
from pathlib import Path

import torch
import aiter  # noqa: F401
from aiter.ops.cache import reshape_and_cache

FP8 = torch.float8_e4m3fn


def topology():
    """Report XCDs per GPU agent via HSA attribute 0xA111."""
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


def write_cache(key, value, k_cache, v_cache, slots, asm, quant, k_scale, v_scale):
    heads, head = key.shape[1], key.shape[2]
    block, x = k_cache.shape[3], k_cache.shape[4]
    for t, slot in enumerate(slots):
        if slot < 0:
            continue
        block_idx, offset = slot // block, slot % block
        k, v = key[t], value[t]
        if quant:
            # Dispatch uses ck_tile::bf16_t (ushort) and ck_tile::fp8_t
            # (_BitInt(8)). The generic scaled_vec_conversion returns its input,
            # so this entry stores the low 8 bits of the bf16 pattern and ignores
            # k_scale / v_scale. The hip_fp8 specialization is selected only for
            # __nv_bfloat16 -> uint8_t, which this dispatch does not use.
            k = (k.view(torch.int16).to(torch.int32) & 0xFF).to(torch.uint8).view(k_cache.dtype)
            v = (v.view(torch.int16).to(torch.int32) & 0xFF).to(torch.uint8).view(v_cache.dtype)
        k_cache[block_idx, :, :, offset, :] = k.reshape(heads, head // x, x)
        if asm:
            v_cache[block_idx, :, offset // x, :, offset % x] = v
        else:
            v_cache[block_idx, :, :, offset] = v


def compare(ref, got, atol, rtol):
    ref_f, got_f = ref.float(), got.float()
    bad = (got_f - ref_f).abs() > (atol + rtol * ref_f.abs())
    return int(bad.sum()), int(bad.numel())


def run_case(stats, dtype, slots, asm=False, quant=False):
    torch.manual_seed(20261111)
    tokens, heads, head, blocks, block, x = 4, 2, 64, 2, 16, 8
    key = torch.randn(tokens, heads, head, dtype=dtype)
    value = torch.randn(tokens, heads, head, dtype=dtype)
    cache_dtype = FP8 if quant else dtype
    k_cache = torch.zeros(blocks, heads, head // x, block, x, dtype=cache_dtype)
    if asm:
        v_cache = torch.zeros(blocks, heads, block // x, head, x, dtype=cache_dtype)
    else:
        v_cache = torch.zeros(blocks, heads, head, block, dtype=cache_dtype)
    k_scale, v_scale = (1.5, 2.0) if quant else (1.0, 1.0)
    k_ref, v_ref = k_cache.clone(), v_cache.clone()
    write_cache(key, value, k_ref, v_ref, slots, asm, quant, k_scale, v_scale)
    k_dev, v_dev = k_cache.cuda(), v_cache.cuda()
    reshape_and_cache(
        key.cuda(), value.cuda(), k_dev, v_dev,
        torch.tensor(slots, dtype=torch.int64, device="cuda"),
        "fp8_e4m3" if quant else "auto", k_scale, v_scale, asm)
    atol = 0.0
    view = (lambda t: t.view(torch.int8)) if quant else (lambda t: t)
    bad_k, n_k = compare(view(k_ref), view(k_dev.cpu()), atol, 0.0)
    bad_v, n_v = compare(view(v_ref), view(v_dev.cpu()), atol, 0.0)
    stats.update(bad_key=bad_k, bad_value=bad_v, elements=n_k + n_v,
                 key_sha256=digest(k_dev), value_sha256=digest(v_dev),
                 grid_x=tokens, asm=asm, quant=quant)
    if bad_k or bad_v:
        raise AssertionError(f"cache mismatch key={bad_k}/{n_k} value={bad_v}/{n_v}")


def expect_reject(fn, text):
    try:
        fn()
    except Exception as exc:
        message = str(exc)
        if text not in message:
            raise AssertionError(message) from exc
        return message.split("\n", 1)[0]
    raise AssertionError("invalid launch configuration accepted")


def one_launch():
    dtype = torch.bfloat16
    key = torch.zeros(2, 1, 16, dtype=dtype, device="cuda")
    value = torch.zeros_like(key)
    k_cache = torch.zeros(1, 1, 2, 8, 8, dtype=dtype, device="cuda")
    v_cache = torch.zeros(1, 1, 16, 8, dtype=dtype, device="cuda")
    slots = torch.zeros(2, dtype=torch.int64, device="cuda")
    reshape_and_cache(key, value, k_cache, v_cache, slots, "auto", 1.0, 1.0, False)


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
    header = dict(op="reshape_and_cache", arch=arch, topology=topo, suite=args.suite,
                  mode=args.die_mode, chunk=args.chunk)
    print(json.dumps(header), flush=True)
    records, failed = [], 0
    cases = {
        "quick": [
            ("bf16_plain", torch.bfloat16, [3, 16, 19, 8], False, False),
            ("fp16_plain", torch.float16, [3, 16, 19, 8], False, False),
            ("bf16_asm", torch.bfloat16, [3, 16, 19, 8], True, False),
            ("bf16_fp8", torch.bfloat16, [3, 16, 19, 8], False, True),
        ],
        "pad": [("bf16_negative_slot", torch.bfloat16, [3, -1, 16, 19], False, False)],
        "route": [("bf16_plain", torch.bfloat16, [3, 16, 19, 8], False, False)],
    }.get(args.suite, [])
    for name, dtype, slots, asm, quant in cases:
        entry = dict(id=name, dtype=str(dtype).replace("torch.", ""), slots=slots)
        try:
            run_case(entry, dtype, slots, asm, quant)
            entry["status"] = "PASS"
        except Exception as exc:
            entry["status"] = "FAIL"
            entry["error"] = str(exc).split("\n", 1)[0]
            failed += 1
        records.append(entry)
        print(json.dumps(entry), flush=True)
    if args.suite == "config":
        checks = [("bad_mode", "nope", None, "AITER_KV_CACHE_DIE_MODE must be auto, off or linear")]
        multi = arch == "gfx946" and any(t["xcds"] >= 2 and t["status"] == 0 for t in topo)
        if multi:
            checks += [
                ("zero_chunk", "linear", "0", "AITER_KV_CACHE_DIE_CHUNK must be positive"),
                ("die_mask", "linear", "1", "AITER_KV_CACHE_DIE_MASK supports only 0"),
            ]
        else:
            text = ("at least 2 reported XCDs" if arch == "gfx946"
                    else "requires a build targeting gfx946")
            checks.append(("linear_rejected", "linear", "1", text))
        for name, mode, chunk, text in checks:
            os.environ["AITER_KV_CACHE_DIE_MODE"] = mode
            if chunk is not None:
                os.environ["AITER_KV_CACHE_DIE_CHUNK"] = chunk
            if name == "die_mask":
                os.environ["AITER_KV_CACHE_DIE_MASK"] = "1"
            entry = dict(id=name)
            try:
                entry["error"] = expect_reject(one_launch, text)
                entry["status"] = "PASS"
            except Exception as exc:
                entry["status"] = "FAIL"
                entry["error"] = str(exc).split("\n", 1)[0]
                failed += 1
            finally:
                os.environ.pop("AITER_KV_CACHE_DIE_MASK", None)
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
