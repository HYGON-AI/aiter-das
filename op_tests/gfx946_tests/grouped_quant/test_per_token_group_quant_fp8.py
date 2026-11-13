# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Standalone per_token_group_quant_fp8 correctness and launch-contract test.

Run from any directory; this checkout takes precedence over an installed wheel.
Only Torch, AITER and the standard library are required. No warmup/timing loops.
PMD environment (set before Python starts):
  export GPU_ARCHS=gfx946 PMD_PATH=/opt/rocm/pmd
  export LD_LIBRARY_PATH=/opt/rocm/lib:/opt/rocm/pmd:${LD_LIBRARY_PATH:-}
  GPU_CHIP=sb python op_tests/gfx946_tests/grouped_quant/test_per_token_group_quant_fp8.py --suite all --expect-xcds 1 --rebuild
  GPU_CHIP=sbx2 python op_tests/gfx946_tests/grouped_quant/test_per_token_group_quant_fp8.py --suite all --expect-xcds 2
  GPU_CHIP=sbx2 python op_tests/gfx946_tests/grouped_quant/test_per_token_group_quant_fp8.py --suite route --expect-xcds 2 --die-mode linear --chunk 2

Use --json to save provenance/results and --list to inspect cases without Torch.
--suite build loads/rebuilds module_quant without dispatching this operator.
Numerical PASS and launch logs do not prove XCD routing: inspect PMD completedWGs
for the named DUT dispatches. PMD results do not validate hardware/Graph/timing.
use_ue8m0 rounds FP32 scales to powers of two; scales are NOT E8M0 byte storage.
"""

import argparse
import ctypes
import ctypes.util
import hashlib
import itertools
import json
import os
from pathlib import Path
import sys

ROOT = Path(__file__).resolve().parents[3]


def matrix():
    cases = []
    for dtype, fmt, ue8m0 in itertools.product(
        ("fp16", "bf16", "fp32"), ("e4m3", "e5m2"), (False, True)
    ):
        cases.append(dict(name=f"g128_{dtype}_{fmt}_ue{int(ue8m0)}", group=128,
                          groups=3, dtype=dtype, fmt=fmt, ue8m0=ue8m0))
    # Every small/large launch specialization, including partial final blocks.
    for i, group in enumerate((16, 32, 64, 256, 512, 1024, 2048, 4096, 8192, 16384)):
        cases.append(dict(name=f"branch_g{group}", group=group,
                          groups=(4096 // group + 1) if group < 1024 else 1,
                          dtype=("fp16", "bf16", "fp32")[i % 3],
                          fmt=("e4m3", "e5m2")[i % 2], ue8m0=bool(i % 2)))
    for pattern, fmt, ue8m0 in itertools.product(
        ("zero", "tiny"), ("e4m3", "e5m2"), (False, True)
    ):
        cases.append(dict(name=f"{pattern}_{fmt}_ue{int(ue8m0)}", group=128,
                          groups=1, dtype="fp32", fmt=fmt, ue8m0=ue8m0, pattern=pattern))
    for layout in ("strided", "3d", "flat_output"):
        cases.append(dict(name=layout, group=128, groups=6, dtype="bf16",
                          fmt="e4m3", ue8m0=False, layout=layout))
    cases.append(dict(name="empty", group=128, groups=0, dtype="fp16",
                      fmt="e4m3", ue8m0=False))
    cases.extend([
        dict(name="route_small", group=128, groups=129, dtype="bf16", fmt="e4m3", ue8m0=False),
        dict(name="route_large", group=1024, groups=5, dtype="fp16", fmt="e5m2", ue8m0=True),
    ])
    return cases


def topology():
    """Read HSA NUM_XCC (0xA111); never infer XCD count from GPU_CHIP/CU count."""
    class Agent(ctypes.Structure):
        _fields_ = [("handle", ctypes.c_uint64)]

    hsa = ctypes.CDLL(ctypes.util.find_library("hsa-runtime64") or "libhsa-runtime64.so.1")
    callback = ctypes.CFUNCTYPE(ctypes.c_uint32, Agent, ctypes.c_void_p)
    hsa.hsa_agent_get_info.argtypes = [Agent, ctypes.c_int, ctypes.c_void_p]
    hsa.hsa_iterate_agents.argtypes = [callback, ctypes.c_void_p]
    agents = []

    @callback
    def visit(agent, _):
        kind, count = ctypes.c_uint32(), ctypes.c_uint32()
        status = hsa.hsa_agent_get_info(agent, 17, ctypes.byref(kind))
        if status or kind.value != 1:
            return status
        name = ctypes.create_string_buffer(64)
        status_name = hsa.hsa_agent_get_info(agent, 0, name)
        status_xcc = hsa.hsa_agent_get_info(agent, 0xA111, ctypes.byref(count))
        agents.append(dict(name=name.value.decode(), xcds=count.value,
                           status_name=status_name, status_xcc=status_xcc))
        return 0

    assert hsa.hsa_init() == 0
    try:
        assert hsa.hsa_iterate_agents(visit, None) == 0
    finally:
        hsa.hsa_shut_down()
    return agents


def digest(tensor):
    return hashlib.sha256(tensor.contiguous().view(torch.uint8).numpy().tobytes()).hexdigest()


def reference(x, group, fmt, ue8m0, eps=1e-5):
    v = x.float().reshape(-1, group)
    scale = v.abs().amax(-1).clamp_min(eps) / torch.finfo(fmt).max
    if ue8m0:
        # eps applies to amax only, not to the already divided scale.
        scale = torch.exp2(torch.ceil(torch.log2(scale)))
    q = (v * scale.reciprocal()[:, None]).to(fmt)
    return q.reshape(x.shape).view(torch.uint8), scale


def run_case(case):
    group, groups = case["group"], case["groups"]
    dtype = {"fp16": torch.float16, "bf16": torch.bfloat16, "fp32": torch.float32}[case["dtype"]]
    fmt = torch.float8_e4m3fn if case["fmt"] == "e4m3" else torch.float8_e5m2
    i = torch.arange(groups * group, dtype=torch.int64)
    cpu = ((((i * 37 + i // 17 * 13) % 1021) - 510).float() / 128).to(dtype)
    cpu = cpu.reshape(groups, group)
    if groups:
        # Explicit signed zero and exact binary values, stable across Torch versions.
        cpu[0, :8] = torch.tensor([0., -0., .5, -.5, 1., -1., 2., -2.], dtype=dtype)
    if case.get("pattern") == "zero":
        cpu.zero_()
        cpu[:, 1] = -0.
    elif case.get("pattern") == "tiny":
        cpu *= 2. ** -24  # amax < eps: catches the old double-clamp reference bug
    layout = case.get("layout")
    if layout == "3d":
        cpu = cpu.reshape(1, 2, 3 * group)
    x = cpu.cuda()
    if layout == "strided":
        # Copy on CPU; only the operator's contiguous conversion executes on GPU.
        padded = torch.full((groups, group * 2), 99., dtype=dtype)
        padded[:, ::2] = cpu
        x = padded.cuda()[:, ::2]
    n = cpu.numel()
    # Guard both ends and poison all output bytes before launch, using CPU buffers.
    qbase = torch.full((n + 64,), 0x55, dtype=torch.uint8).cuda()
    sbase = torch.full((groups + 64,), -123., dtype=torch.float32).cuda()
    q = qbase[32:32 + n].view(fmt).reshape(cpu.shape)
    scales = sbase[32:32 + groups]
    if layout == "flat_output":
        q = q.flatten()  # buffers have a numel contract, not a prescribed rank
    torch.cuda.synchronize()
    print("DUT_BEGIN", case["name"], flush=True)
    aiter.per_token_group_quant_fp8(q, x, scales, group, 1e-5, case["ue8m0"])
    torch.cuda.synchronize()
    print("DUT_END", case["name"], flush=True)
    actual_q, actual_s = qbase.cpu(), sbase.cpu()
    assert torch.equal(actual_q[:32], torch.full((32,), 0x55, dtype=torch.uint8))
    assert torch.equal(actual_q[-32:], torch.full((32,), 0x55, dtype=torch.uint8))
    assert (actual_s[:32] == -123.).all() and (actual_s[-32:] == -123.).all()
    qref, sref = reference(cpu, group, fmt, case["ue8m0"])
    got_q, got_s = actual_q[32:32 + n], actual_s[32:32 + groups]
    # Strict FP8 payload comparison, including signed zeros; never tolerate bad lanes.
    assert torch.equal(got_q, qref.flatten()), (
        case["name"], "FP8 byte mismatches", int((got_q != qref.flatten()).sum()))
    # FP32 reciprocal/divide may differ by a few ULP; no absolute tolerance that
    # could hide a missing/tiny scale. UE8M0 powers of two must be exact.
    torch.testing.assert_close(got_s, sref, rtol=0 if case["ue8m0"] else 2e-6, atol=0)
    grid = (groups + 4096 // group - 1) // (4096 // group) if group < 1024 else groups
    result = dict(case=case, grid=grid, input_sha256=digest(cpu), output_sha256=digest(got_q),
                  scale_sha256=digest(got_s), status="PASS")
    print("PASS", case["name"], flush=True)
    return result


def contracts(arch, xcds):
    x = torch.ones((2, 128), dtype=torch.float16).cuda()
    q = torch.empty(x.shape, dtype=torch.float8_e4m3fn).cuda()
    s = torch.empty((2,), dtype=torch.float32).cuda()
    results = []

    def reject(name, expected, *, output=q, input=x, scales=s, group=128, eps=1e-5):
        try:
            aiter.per_token_group_quant_fp8(output, input, scales, group, eps, False)
        except (RuntimeError, ValueError) as error:
            assert expected in str(error), (name, str(error))
        else:
            raise AssertionError(f"{name}: invalid request was accepted")
        results.append(dict(name=name, status="PASS"))
        print("PASS reject", name, flush=True)

    for group in (0, -16, 8, 48, 32768, 2 ** 32 + 128):
        reject(f"group_{group}", "power of 2", group=group)
    reject("hidden", "hidden_size", input=x[:, :127])
    for eps in (0., -1., float("inf"), float("nan")):
        reject(f"eps_{eps}", "eps", eps=eps)
    reject("out_numel", "same numel", output=q.flatten()[:128])
    reject("scales_numel", "one element per group", scales=s[:1])
    reject("scales_dtype", "scales must be float32", scales=torch.empty(2, dtype=torch.float16).cuda())
    reject("out_dtype", "Output tensor", output=torch.empty(x.shape, dtype=torch.uint8).cuda())
    reject("fnuz", "Output tensor", output=torch.empty(x.shape, dtype=torch.float8_e4m3fnuz).cuda())
    reject("input_dtype", "input must be", input=torch.ones(x.shape, dtype=torch.int32).cuda())
    reject("input_rank", "at least one dimension", input=torch.tensor(1., dtype=torch.float16).cuda())
    reject("out_stride", "out must be contiguous", output=q.t())
    reject("scale_stride", "scales must be contiguous", scales=torch.empty(4).cuda()[::2])
    reject("cpu_input", "GPU tensors", input=x.cpu())
    reject("cpu_output", "GPU tensors", output=q.cpu())
    reject("cpu_scales", "GPU tensors", scales=s.cpu())
    names = ("AITER_QUANT_DIE_MODE", "AITER_QUANT_DIE_CHUNK", "AITER_QUANT_DIE_MASK")
    saved = {name: os.environ.get(name) for name in names}
    try:
        os.environ[names[0]] = "bad-mode"
        reject("bad_mode", "must be auto, off or linear")
        os.environ[names[0]] = "linear"
        if arch != "gfx946" or xcds < 2:
            reject("linear_unsupported", "linear launch requires")
        else:
            for value in ("0", "-1", "", "abc", "4294967296"):
                os.environ[names[1]] = value
                reject(f"chunk_{value}", "AITER_QUANT_DIE_CHUNK")
            os.environ[names[1]] = "1"
            for value in ("1", "-1", "abc"):
                os.environ[names[2]] = value
                reject(f"mask_{value}", "AITER_QUANT_DIE_MASK")
    finally:
        for name, value in saved.items():
            if value is None:
                os.environ.pop(name, None)
            else:
                os.environ[name] = value
    return results


def main():
    ap = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    ap.add_argument("--suite", choices=("quick", "full", "route", "config", "all", "build"), default="quick")
    ap.add_argument("--case")
    ap.add_argument("--list", action="store_true")
    ap.add_argument("--rebuild", action="store_true")
    ap.add_argument("--require-arch", default="gfx946")
    ap.add_argument("--expect-xcds", type=int)
    ap.add_argument("--die-mode", choices=("auto", "off", "linear"), default="auto")
    ap.add_argument("--chunk", type=int, default=1)
    ap.add_argument("--json", type=Path)
    args = ap.parse_args()
    cases = matrix()
    if args.list:
        print(json.dumps(cases, indent=2))
        return
    if args.case:
        cases = [case for case in cases if case["name"] == args.case]
        if not cases:
            ap.error("unknown --case")
    elif args.suite == "quick":
        cases = [case for case in cases if case["name"].startswith("g128_fp16_")]
    elif args.suite == "route":
        cases = [case for case in cases if case["name"].startswith("route_")]
    elif args.suite in ("config", "build"):
        cases = []
    if args.rebuild:
        os.environ["AITER_REBUILD"] = "1"
    os.environ["AITER_QUANT_DIE_MODE"] = args.die_mode
    os.environ["AITER_QUANT_DIE_CHUNK"] = str(args.chunk)
    os.environ["AITER_QUANT_LOG_LAUNCH"] = "1"
    sys.path.insert(0, str(ROOT))
    global torch, aiter
    import torch
    import aiter
    from aiter.jit.core import get_module

    assert Path(aiter.__file__).resolve().parent == ROOT / "aiter", aiter.__file__
    torch.set_num_threads(1)
    # Invoke the real wrapper with CPU tensors. A deliberate host-side contract
    # rejection loads JIT and verifies the new source without launching a kernel.
    try:
        aiter.per_token_group_quant_fp8(torch.empty(0, dtype=torch.float8_e4m3fn),
                                      torch.empty((0, 128)), torch.empty(0), 128)
    except RuntimeError as error:
        assert "GPU tensors" in str(error), str(error)
    else:
        raise AssertionError("CPU build probe unexpectedly accepted")
    module = get_module("module_quant")
    module_path = Path(module.__file__).resolve()
    info = dict(torch=torch.__version__, aiter=aiter.__file__, module=str(module_path),
                module_sha256=hashlib.sha256(module_path.read_bytes()).hexdigest(),
                sources={str(p): hashlib.sha256((ROOT / p).read_bytes()).hexdigest() for p in (
                    Path("csrc/kernels/per_token_group_quant_fp8_kernels.cu"),
                    Path("csrc/include/hip_kernel_launch.h"), Path("aiter/jit/core.py"),
                    Path(__file__).resolve().relative_to(ROOT))},
                args=vars(args) | {"json": str(args.json)}, results=[], contracts=[])
    if args.suite != "build":
        torch.cuda.init()
        props = torch.cuda.get_device_properties(0)
        arch = props.gcnArchName.split(":")[0]
        assert arch == args.require_arch, (arch, args.require_arch)
        agents = topology() if arch == "gfx946" else []
        xcds = 0
        if arch == "gfx946":
            # This test targets one GPU with multiple dies, not multiple GPUs.
            assert torch.cuda.device_count() == 1 and len(agents) == 1, agents
            assert agents[0]["status_xcc"] == 0 and agents[0]["xcds"] > 0, agents
            xcds = agents[0]["xcds"]
        if args.expect_xcds is not None:
            assert xcds == args.expect_xcds, (xcds, args.expect_xcds)
        info.update(arch=arch, topology=agents, device=str(props), gpu_chip=os.environ.pop("GPU_CHIP", None))
        print("ENV", json.dumps(info), flush=True)
        for case in cases:
            info["results"].append(run_case(case))
        if args.suite in ("all", "config") and not args.case:
            info["contracts"] = contracts(arch, xcds)
    info["status"] = "PASS"
    if args.json:
        args.json.parent.mkdir(parents=True, exist_ok=True)
        args.json.write_text(json.dumps(info, indent=2) + "\n")
    print("SUMMARY", json.dumps(dict(status="PASS", numerical=len(info["results"]),
                                     contracts=len(info["contracts"]), module=str(module_path),
                                     module_sha256=info["module_sha256"])), flush=True)


if __name__ == "__main__":
    main()
