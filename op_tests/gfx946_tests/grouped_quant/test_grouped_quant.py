# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Self-contained grouped INT8/E4M3 and MXFP4 validation/profiling.

Only stdlib, torch and installed AITER are required. No scratch imports/data.
From the AITER root, after building module_quant for the target:
  python op_tests/gfx946_tests/grouped_quant/test_grouped_quant.py --suite full
PMD environment (choose sb/1 or sbx2/2 before HIP initialization):
  export GPU_ARCHS=gfx946 GPU_CHIP=sbx2 PMD_PATH=/opt/rocm/pmd
  export LD_LIBRARY_PATH=/opt/rocm/lib:/opt/rocm/pmd:$LD_LIBRARY_PATH
  python op_tests/gfx946_tests/grouped_quant/test_grouped_quant.py --suite full --expect-xcds 2
  python op_tests/gfx946_tests/grouped_quant/test_grouped_quant.py --case fp4_m96 --die-mode linear --chunk 2 --expect-xcds 2
  python op_tests/gfx946_tests/grouped_quant/test_grouped_quant.py --suite config --expect-xcds 2
--list prints the common performance matrix without initializing HIP.
--case runs one public wrapper once unless --warmup/--repeat are specified.
Timing excludes input/CPU reference/copies; GPU events include wrapper overhead
between launches. Raw profiler kernel duration is reported separately by tooling.
Numerical PASS does not establish multi-XCD routing: inspect completedWGs.
PMD CPU wall time is not GPU performance. No Graph claim is made.
"""
import argparse
import ctypes
import ctypes.util
import hashlib
import json
import os
from pathlib import Path
import sys


def matrix():
    cases = []
    for op in ("fp4", "fp8", "int8", "e8m0"):
        for m in (1, 48, 96, 192):
            cases.append(dict(name=f"{op}_m{m}", op=op, m=m, n=2048, group=32 if op == "fp4" else 128, layout=False))
        cases.append(dict(name=f"{op}_tail", op=op, m=3, n=96 if op == "fp4" else 384, group=32 if op == "fp4" else 128, layout=True))
    cases += [dict(name="fp4_shuffle", op="fp4", m=33, n=256, group=32, layout=True),
              dict(name="fp8_g32", op="fp8", m=5, n=96, group=32, layout=False),
              dict(name="int8_g64", op="int8", m=5, n=192, group=64, layout=True)]
    return cases


def topology():
    class Agent(ctypes.Structure):
        _fields_ = [("handle", ctypes.c_uint64)]
    hsa = ctypes.CDLL(ctypes.util.find_library("hsa-runtime64") or "libhsa-runtime64.so.1")
    callback = ctypes.CFUNCTYPE(ctypes.c_uint32, Agent, ctypes.c_void_p)
    hsa.hsa_agent_get_info.argtypes = [Agent, ctypes.c_int, ctypes.c_void_p]
    hsa.hsa_iterate_agents.argtypes = [callback, ctypes.c_void_p]
    result = []
    @callback
    def visit(agent, unused):
        kind, count = ctypes.c_uint32(), ctypes.c_uint32()
        status = hsa.hsa_agent_get_info(agent, 17, ctypes.byref(kind))
        if status or kind.value != 1:
            return status
        name = ctypes.create_string_buffer(64)
        hsa.hsa_agent_get_info(agent, 0, name)
        status = hsa.hsa_agent_get_info(agent, 0xA111, ctypes.byref(count))
        result.append(dict(name=name.value.decode(), xcds=count.value, status=status))
        return 0
    assert hsa.hsa_init() == 0
    try:
        assert hsa.hsa_iterate_agents(visit, None) == 0
    finally:
        hsa.hsa_shut_down()
    return result


def digest(t):
    return hashlib.sha256(t.contiguous().view(torch.uint8).numpy().tobytes()).hexdigest()


def make_input(c, dtype, zero=False):
    # Integer arithmetic and exact binary fractions are stable across Torch versions.
    i = torch.arange(c["m"] * c["n"], dtype=torch.int64)
    x = (((i * 37 + i // 17 * 13) % 1021) - 510).float() / 128
    x = x.reshape(c["m"], c["n"]).to(dtype)
    if x.numel():
        x.reshape(-1)[:32] = 0  # all-zero group and signed zero
        if x.numel() > 64:
            x.reshape(-1)[32:64] = torch.tensor([-.25, .25, -.75, .75, -1.25, 1.25, -1.75, 1.75,
                                                -2.5, 2.5, -3.5, 3.5, -5., 5., -6., 6.]).repeat(2).to(dtype)
    if zero:
        x.zero_()
    return x


def reference(cpu, c):
    v = cpu.float().reshape(c["m"], c["n"] // c["group"], c["group"])
    amax = v.abs().amax(-1).clamp_min(1e-10)
    if c["op"] == "fp4":
        bits = amax.contiguous().view(torch.int32).to(torch.int64)
        exponent = (bits >> 23) & 255
        bump = ((bits & 0x400000) != 0) & (((bits & 0x3fffff) != 0) | (exponent != 0))
        exponent += bump
        scale = torch.pow(2., exponent.float() - 129)
        z = v / scale[..., None]
        values = torch.tensor([0., .5, 1., 1.5, 2., 3., 4., 6.])
        dist = (z.abs()[..., None] - values).abs()
        best = dist.amin(-1, keepdim=True)
        # Exact ties choose the even encoded significand.
        rank = torch.tensor([0, 9, 2, 11, 4, 13, 6, 15])
        choice = torch.where(dist == best, rank, 99).argmin(-1).to(torch.uint8)
        choice |= torch.signbit(z).to(torch.uint8) << 3
        q = choice.reshape(c["m"], c["n"])
        return q[:, ::2] | (q[:, 1::2] << 4), (exponent - 2).to(torch.uint8)
    limit = 127. if c["op"] == "int8" else 448.
    scale = amax * torch.tensor(1. / limit, dtype=torch.float32)
    if c["op"] == "e8m0":
        scale = torch.pow(2., torch.ceil(torch.log2(scale)))
    mult = limit / amax if c["op"] == "int8" else 1. / scale
    z = v * mult[..., None]
    q = z.round().to(torch.int8) if c["op"] == "int8" else z.to(torch.float8_e4m3fn)
    stored_scale = (scale.contiguous().view(torch.int32) >> 23).to(torch.uint8) if c["op"] == "e8m0" else scale
    return q.reshape(c["m"], c["n"]).view(torch.uint8), stored_scale


def scale_indices(c, active):
    groups = c["n"] // c["group"]
    r = torch.arange(active)[:, None]
    g = torch.arange(groups)[None, :]
    if c["op"] == "fp4" and c["layout"]:
        pad = (groups + 7) // 8 * 8
        return ((r // 32 * pad) * 32 + g // 8 * 256 + g % 4 * 64 + r % 16 * 4 + g % 8 // 4 * 2 + r % 32 // 16).flatten()
    if c["layout"]:
        return (g * c["m"] + r).flatten()
    return (r * groups + g).flatten()


def run(c, dtype, args, guarded=False, prefix=None, factor=1, zero=False, three_d=False, strided=False):
    cpu = make_input(c, dtype, zero)
    qref, sref = reference(cpu, c)
    active = c["m"] if prefix is None else min(c["m"], max(0, prefix * factor))
    device_cpu = cpu
    if strided:
        device_cpu = torch.full((c["m"], c["n"] + 32), 99., dtype=dtype)
        device_cpu[:, :c["n"]] = cpu
    base = device_cpu.cuda()
    x = base[:, :c["n"]] if strided else base
    if three_d:
        x = x.reshape(1, c["m"], c["n"])
    qdtype = aiter.dtypes.fp4x2 if c["op"] == "fp4" else (torch.int8 if c["op"] == "int8" else torch.float8_e4m3fn)
    opts = {} if prefix is None else dict(num_rows=torch.tensor([prefix], dtype=torch.int32).cuda(), num_rows_factor=factor)
    groups = c["n"] // c["group"]
    ns = ((c["m"] + 255) // 256 * 256) * ((groups + 7) // 8 * 8) if c["op"] == "fp4" and c["layout"] else c["m"] * groups
    nq = c["m"] * c["n"] // (2 if c["op"] == "fp4" else 1)
    if guarded:
        qb = torch.full((nq + 64,), 83, dtype=torch.uint8).cuda()
        sb = torch.full((ns + 64,), 83 if c["op"] in ("fp4", "e8m0") else -11,
                        dtype=torch.uint8 if c["op"] in ("fp4", "e8m0") else torch.float32).cuda()
        q = qb[32:-32].view(qdtype).reshape(c["m"], c["n"] // (2 if c["op"] == "fp4" else 1))
        scale = sb[32:-32]
        from aiter.ops.quant import _dynamic_per_group_quant
        def call():
            if c["op"] == "fp4":
                aiter.dynamic_per_group_scaled_quant_fp4(q, x, scale, c["group"], shuffle_scale=c["layout"], **opts)
            else:
                _dynamic_per_group_quant(q, x.reshape(-1, c["group"]), scale, shuffle_scale=c["layout"], **opts)
            return q, scale
    else:
        def call():
            if c["op"] == "fp4":
                return aiter.per_1x32_f4_quant_hip(x, shuffle=c["layout"], **opts)
            return aiter.per_group_quant_hip(x, quant_dtype=qdtype, group_size=c["group"], transpose_scale=c["layout"],
                                            scale_type=aiter.dtypes.fp8_e8m0 if c["op"] == "e8m0" else torch.float32, **opts)
    torch.cuda.synchronize()
    print("DUT_BEGIN", c["name"], flush=True)
    for _ in range(args.warmup):
        call()
    times = []
    for _ in range(args.repeat):
        if args.events:
            start, end = torch.cuda.Event(enable_timing=True), torch.cuda.Event(enable_timing=True)
            start.record()
        q, scale = call()
        if args.events:
            end.record(); end.synchronize(); times.append(start.elapsed_time(end) * 1000)
    torch.cuda.synchronize()
    print("DUT_END", c["name"], flush=True)
    actual = q.view(torch.uint8).cpu().reshape(c["m"], c["n"] // (2 if c["op"] == "fp4" else 1))[:active]
    assert torch.equal(actual, qref[:active]), f"{c['name']} quant bytes mismatch {(actual != qref[:active]).sum().item()}"
    rawscale = scale.view(torch.uint8).cpu().flatten() if c["op"] in ("fp4", "e8m0") else scale.cpu().flatten()
    indices = scale_indices(c, active)
    actual_s = rawscale[indices]
    expected_s = sref[:active].flatten()
    assert torch.equal(actual_s, expected_s), f"{c['name']} scale mismatch {actual_s[:16]} vs {expected_s[:16]}"
    assert torch.equal(base.cpu(), device_cpu), "input changed"
    if guarded:
        rawq, raws = qb.cpu(), sb.cpu()
        assert (rawq[:32] == 83).all() and (rawq[-32:] == 83).all(), "output guard"
        sentinel = 83 if c["op"] in ("fp4", "e8m0") else -11
        assert (raws[:32] == sentinel).all() and (raws[-32:] == sentinel).all(), "scale guard"
        assert (rawq[32 + active * c["n"] // (2 if c["op"] == "fp4" else 1):-32] == 83).all(), "inactive output"
        untouched = torch.ones(ns, dtype=torch.bool); untouched[indices] = False
        assert (raws[32:-32][untouched] == sentinel).all(), "inactive/padded scale"
    result = dict(case=c, dtype=str(dtype), input_sha256=digest(cpu), output_sha256=digest(actual),
                  scale_sha256=digest(actual_s), active_rows=active, guarded=guarded, prefix=prefix,
                  factor=factor, zero=zero, three_d=three_d, strided=strided, event_us=times, passed=True)
    print("PASS", c["name"], str(dtype), "guarded", guarded, "prefix", prefix, flush=True)
    return result


def main():
    ap = argparse.ArgumentParser(description=__doc__)
    ap.add_argument("--list", action="store_true")
    ap.add_argument("--case")
    ap.add_argument("--suite", choices=("quick", "full", "boundaries", "config"), default="quick")
    ap.add_argument("--dtype", choices=("bf16", "fp16"), default="bf16")
    ap.add_argument("--expect-xcds", type=int)
    ap.add_argument("--require-arch")
    ap.add_argument("--die-mode", default="auto")
    ap.add_argument("--chunk", type=int, default=1)
    ap.add_argument("--warmup", type=int, default=0)
    ap.add_argument("--repeat", type=int, default=1)
    ap.add_argument("--events", action="store_true")
    ap.add_argument("--json", type=Path)
    args = ap.parse_args()
    if args.list:
        print(json.dumps(matrix())); return
    global torch, aiter
    import torch
    import aiter
    torch.set_num_threads(1)
    torch.cuda.init()
    props = torch.cuda.get_device_properties(0)
    arch = props.gcnArchName.split(":")[0]
    topo = topology() if arch == "gfx946" else []
    if args.require_arch:
        assert arch == args.require_arch, arch
    if args.expect_xcds:
        assert any(t["status"] == 0 and t["xcds"] == args.expect_xcds for t in topo), topo
    os.environ.pop("GPU_CHIP", None)  # launcher must use device topology
    os.environ["AITER_QUANT_DIE_MODE"] = args.die_mode
    os.environ["AITER_QUANT_DIE_CHUNK"] = str(args.chunk)
    info = dict(torch=torch.__version__, aiter=aiter.__file__, arch=arch, topology=topo,
                device=str(props), warmup=args.warmup, repeat=args.repeat, results=[])
    print("ENV", json.dumps(info), flush=True)
    dtype = torch.bfloat16 if args.dtype == "bf16" else torch.float16
    cases = matrix()
    if args.case:
        cases = [next(c for c in cases if c["name"] == args.case)]
    elif args.suite == "quick":
        cases = [c for c in cases if c["name"].endswith("tail") or c["name"] == "fp4_shuffle"]
    elif args.suite == "boundaries":
        cases = []
    if args.suite == "config":
        # Declaring/viewing FNUZ storage is allowed by Torch. AITER must reject
        # execution, including callers that bypass the public Python wrapper.
        from aiter.ops.quant import _dynamic_per_group_quant
        x = torch.empty((1, 32), dtype=dtype, device="cuda")
        qraw = torch.empty((1, 32), dtype=torch.uint8, device="cuda")
        sraw = torch.empty((1, 1), dtype=torch.uint8, device="cuda")
        bad = torch.float8_e4m3fnuz
        sf = torch.empty((1, 1), dtype=torch.float32, device="cuda")
        tests = [
            ("wrapper_output_fnuz", lambda: aiter.per_group_quant_hip(x, quant_dtype=bad, group_size=32), "group quant output"),
            ("wrapper_scale_fnuz", lambda: aiter.per_group_quant_hip(x, quant_dtype=torch.float8_e4m3fn, group_size=32, scale_type=bad), "group scale"),
            ("fp4_wrapper_fnuz", lambda: aiter.per_1x32_f4_quant_hip(x, quant_dtype=bad), "packed FP4"),
            ("native_group_output_fnuz", lambda: _dynamic_per_group_quant(qraw.view(bad), x, sf), "float8_e4m3fnuz"),
            ("native_group_scale_fnuz", lambda: _dynamic_per_group_quant(qraw.view(torch.float8_e4m3fn), x, sraw.view(bad)), "float8_e4m3fnuz"),
            ("native_fp4_output_fnuz", lambda: aiter.dynamic_per_group_scaled_quant_fp4(qraw[:, :16].view(bad), x, sraw, 32, False), "float8_e4m3fnuz"),
            ("native_fp4_scale_fnuz", lambda: aiter.dynamic_per_group_scaled_quant_fp4(qraw[:, :16], x, sraw.view(bad), 32, False), "float8_e4m3fnuz"),
        ]
        print("FNUZ_REJECTION_BEGIN", flush=True)
        for label, call, message in tests:
            try:
                call()
            except (RuntimeError, ValueError) as exc:
                assert message in str(exc), (label, str(exc))
                info["results"].append(dict(test=label, rejected=True, error=str(exc)))
                print("PASS", label, "rejected", flush=True)
            else:
                raise AssertionError(label + " was allowed to execute")
        torch.cuda.synchronize()
        print("FNUZ_REJECTION_END", flush=True)
        multi = any(t["status"] == 0 and t["xcds"] >= 2 for t in topo)
        for op in ("fp4", "fp8"):
            c = dict(name="config_" + op, op=op, m=33, n=256, group=32, layout=True)
            invalid = [("AITER_QUANT_DIE_MODE", "invalid")]
            if multi:
                invalid += [("AITER_QUANT_DIE_CHUNK", v) for v in ("0", "-1", "bad")]
                invalid += [("AITER_QUANT_DIE_MASK", "1")]
            else:
                invalid += [("AITER_QUANT_DIE_MODE", "linear")]
            for key, value in invalid:
                os.environ["AITER_QUANT_DIE_MODE"] = "auto"
                os.environ[key] = value
                try:
                    run(c, dtype, args)
                except (RuntimeError, ValueError):
                    info["results"].append(dict(op=op, config=key, value=value, rejected=True))
                else:
                    raise AssertionError("invalid config accepted")
                os.environ.pop(key, None)
            os.environ["AITER_QUANT_DIE_MODE"] = "off"
            info["results"].append(run(c, dtype, args))
            if multi:
                os.environ["AITER_QUANT_DIE_MODE"] = "linear"
                os.environ["AITER_QUANT_DIE_CHUNK"] = "2"
                info["results"].append(run(c, dtype, args))
            os.environ["AITER_QUANT_DIE_CHUNK"] = str(args.chunk)
    else:
        for c in cases:
            info["results"].append(run(c, dtype, args))
        if args.suite in ("full", "boundaries") and not args.case:
            for op in ("fp4", "fp8", "int8", "e8m0"):
                for group in ((32,) if op == "fp4" else (32, 64, 128)):
                    c = dict(name=f"boundary_{op}_{group}", op=op, m=5, n=group*3, group=group, layout=True)
                    for prefix, factor in ((None, 1), (2, 2), (0, 1), (99, 1), (-1, 1)):
                        info["results"].append(run(c, dtype, args, guarded=True, prefix=prefix, factor=factor, strided=op == "fp4"))
                    c["layout"] = False
                    info["results"].append(run(c, dtype, args, zero=True, three_d=op != "fp4"))
                    c["n"] = group
                    info["results"].append(run(c, dtype, args))
                    c["m"] = 0
                    info["results"].append(run(c, dtype, args))
    modules = {}
    for name, module in list(sys.modules.items()):
        path = getattr(module, "__file__", "") or ""
        if "module_quant" in name and path.endswith(".so"):
            modules[name] = dict(path=path, sha256=hashlib.sha256(Path(path).read_bytes()).hexdigest())
    info["modules"] = modules
    if args.json:
        args.json.write_text(json.dumps(info, indent=2))
    print("SUMMARY", len(info["results"]), "PASS", json.dumps(modules), flush=True)


if __name__ == "__main__":
    main()
