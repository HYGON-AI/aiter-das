# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# moe_swiglu_dynamic_quant 的 gfx946 单 die / 多 die 测试。只依赖已安装的
# AITER、Torch 和 Python 标准库；不读取临时目录、生成器或旧结果文件。
#
# 在装有 gfx946 perf model 的环境中，先确认使用的是预期的 AITER 源码与缓存，
# 再编译 gfx946 的 module_quant（以下命令在 AITER 仓库根目录执行）：
#   export GPU_ARCHS=gfx946 PMD_PATH=/opt/rocm/pmd
#   export LD_LIBRARY_PATH=/opt/rocm/lib:/opt/rocm/pmd:${LD_LIBRARY_PATH:-}
#   unset AITER_JIT_DIR PYTHONPATH AITER_REBUILD
# 若环境中已安装 AITER 并遮蔽了当前仓库，import 会落到安装位置、从而编译到
# 另一份源码；此时需显式把本仓库放进 PYTHONPATH。输出中的 aiter 路径与
# module_quant.so 的 sha256 可用于核对实际使用的源码与二进制。
#
# 单 die（PMD 单 XCD）：
#   export GPU_CHIP=sb
#   python op_tests/gfx946_tests/test_moe_swiglu_dynamic_quant.py --suite quick --expect-xcds 1
#   python op_tests/gfx946_tests/test_moe_swiglu_dynamic_quant.py --suite unassigned --expect-xcds 1
#   python op_tests/gfx946_tests/test_moe_swiglu_dynamic_quant.py --suite zero --expect-xcds 1
#   python op_tests/gfx946_tests/test_moe_swiglu_dynamic_quant.py --suite config --expect-xcds 1
#
# 多 die（PMD 双 XCD）：
#   export GPU_CHIP=sbx2
#   python op_tests/gfx946_tests/test_moe_swiglu_dynamic_quant.py --suite quick --expect-xcds 2
#   python op_tests/gfx946_tests/test_moe_swiglu_dynamic_quant.py --suite unassigned --expect-xcds 2
#   python op_tests/gfx946_tests/test_moe_swiglu_dynamic_quant.py --suite zero --expect-xcds 2
#   python op_tests/gfx946_tests/test_moe_swiglu_dynamic_quant.py --suite route --die-mode linear --chunk 1 --expect-xcds 2
#   python op_tests/gfx946_tests/test_moe_swiglu_dynamic_quant.py --suite route --die-mode linear --chunk 2 --expect-xcds 2
#   python op_tests/gfx946_tests/test_moe_swiglu_dynamic_quant.py --suite config --expect-xcds 2
#
# full 覆盖 d 的每个 kernel 分支，大 d 在 CPU 模拟器上很慢，按 dtype 拆进程：
#   python op_tests/gfx946_tests/test_moe_swiglu_dynamic_quant.py --suite full --dtypes bf16 --max-d 4096
# stride 触发 grid.x < num_tokens 的 grid-stride 路径，token 数较大，默认不跑：
#   python op_tests/gfx946_tests/test_moe_swiglu_dynamic_quant.py --suite stride
#
# --die-mode 默认 auto，按 HIP 报告的 numXcc 选择普通或多 die 启动；off 使用
# 普通启动，并不证明只使用一个 XCD。模型选择必须在 Python/HIP 初始化之前由
# 外部 GPU_CHIP 完成，算子本身不读该变量。数值通过和启动日志都不能单独证明
# 两个 XCD 都执行了 TG，需另外查看 PMD 每个 dispatch 的 completedWGs。
# 真实 gfx946 使用实际设备拓扑，不需要设置 GPU_CHIP；PMD 不是性能基准。
"""Single-die / multi-die checks of aiter.moe_swiglu_dynamic_quant on gfx946."""
import argparse
import ctypes
import ctypes.util
import hashlib
import json
import os
from pathlib import Path
import sys
import time

import torch
import aiter
from aiter.ops.quant import moe_swiglu_dynamic_quant_wrapper

DTYPES = {"fp16": torch.float16, "bf16": torch.bfloat16}
LOG2E = 1.44269504088896340736
# The device silu uses __builtin_amdgcn_exp2f, a ~1 ULP hardware approximation.
# The reference is evaluated at the nominal result and at +/- this relative
# perturbation; the accepted band is the elementwise envelope of the three runs.
EXP2_ULP = 2.0 ** -22
MAX_EXPERTS = 64  # mirrors kMoeSwigluMaxExperts in csrc/kernels/quant_kernels.cu


def topology():
    """Report XCDs per GPU agent via HSA_AMD_AGENT_INFO_NUM_XCC (0xA111)."""
    class Agent(ctypes.Structure):
        _fields_ = [("handle", ctypes.c_uint64)]
    hsa = ctypes.CDLL(ctypes.util.find_library("hsa-runtime64") or "libhsa-runtime64.so.1")
    cb_type = ctypes.CFUNCTYPE(ctypes.c_uint32, Agent, ctypes.c_void_p)
    hsa.hsa_agent_get_info.argtypes = [Agent, ctypes.c_int, ctypes.c_void_p]
    hsa.hsa_iterate_agents.argtypes = [cb_type, ctypes.c_void_p]
    result = []

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
        result.append(dict(name=name.value.decode(), xcds=count.value, status=status))
        return 0

    assert hsa.hsa_init() == 0
    try:
        assert hsa.hsa_iterate_agents(visit, None) == 0
    finally:
        assert hsa.hsa_shut_down() == 0
    return result


def vec_width(d):
    """Vector width of the kernel branch the host launcher picks for this d."""
    return 2 if d <= 512 else 16 if d <= 16384 else 32 if d <= 32768 else 1


def kernel_branch(d):
    if d <= 512:
        return "block_vec2_b256"
    if d <= 1024:
        return "one_warp_vec16_b64"
    if d <= 2048:
        return "block_vec16_b128"
    if d <= 4096:
        return "block_vec16_b256"
    if d <= 8192:
        return "block_vec16_b512"
    if d <= 16384:
        return "block_vec16_b1024"
    if d <= 32768:
        return "block_vec32_b1024"
    return "scalar_fallback_b1024"


def grid_x(num_tokens):
    """Mirror the host launcher's grid_opt compression."""
    if num_tokens in (9216, 10240, 11264, 12288, 13312, 14336):
        return 8192
    if num_tokens in (3072, 4096, 5120, 6144, 7168):
        return 2048
    if 1024 <= num_tokens <= 2048:
        return 1024
    return num_tokens


# ---------------------------------------------------------------------------
# Inputs and CPU reference
# ---------------------------------------------------------------------------
def cpu_inputs(num_tokens, d, num_experts, dtype, pattern, seed):
    g = torch.Generator().manual_seed(seed)
    x = torch.randn(num_tokens, 2 * d, generator=g)
    # Row-dependent scaling exercises a wide range of per-token absmax values.
    x *= (torch.arange(num_tokens).float()[:, None] + 1) * 0.25
    if pattern == "zero":
        x.zero_()
    elif pattern == "mixed_zero":
        x[::2] = 0
    elif pattern == "saturate":
        # Values far apart in magnitude push the quantized row to the clamps.
        x[:, 0] = 300.0
    smooth = torch.rand((num_experts, d), generator=g) * 1.5 + 0.25
    return x.to(dtype), smooth


def expert_metadata(num_tokens, num_experts, layout):
    """Return (count, start, covered_tokens) as int32 CPU tensors."""
    count = torch.zeros(num_experts, dtype=torch.int32)
    if layout == "even":
        base, extra = divmod(num_tokens, num_experts)
        count.fill_(base)
        count[:extra] += 1
    elif layout == "empty_tail":
        # Half the experts receive nothing; all tokens are still covered.
        half = max(1, num_experts // 2)
        base, extra = divmod(num_tokens, half)
        count[:half] = base
        count[:extra] += 1
    elif layout == "uncovered_tail":
        # The last quarter of the tokens belongs to no expert at all.
        covered = max(1, (num_tokens * 3) // 4)
        base, extra = divmod(covered, num_experts)
        count.fill_(base)
        count[:extra] += 1
    else:
        raise ValueError(layout)
    start = torch.zeros(num_experts, dtype=torch.int32)
    start[1:] = torch.cumsum(count, 0)[:-1].to(torch.int32)
    return count, start, int(count.sum())


def reference_once(x, smooth, count, start, dtype, pert):
    """One FP32 CPU evaluation of the kernel's arithmetic for a given exp2 bias."""
    num_tokens, d2 = x.shape
    d = d2 // 2
    gate, up = x[:, :d], x[:, d:]

    # silu_kernel casts its FP32 result back to scalar_t before the products.
    gf = gate.float()
    e = torch.exp2(-gf * LOG2E) * pert
    silu = (gf / (1.0 + e)).to(dtype).float()
    act = silu * up.float()

    expert_of = torch.full((num_tokens,), -1, dtype=torch.long)
    for e_idx in range(count.numel()):
        c, s = int(count[e_idx]), int(start[e_idx])
        if c > 0:
            expert_of[s:s + c] = e_idx
    assigned = expert_of >= 0

    row = act * smooth[expert_of.clamp_min(0)]
    row_max = row.abs().amax(-1)
    scales = row_max / 127.0
    inv = torch.where(row_max > 0, 127.0 / row_max, torch.zeros_like(row_max))
    q = (row * inv[:, None]).round().clamp(-128, 127)

    # Tokens outside every expert range get a defined zero row and zero scale.
    q[~assigned] = 0
    scales[~assigned] = 0.0
    return q.to(torch.int8), scales


def reference_band(x, smooth, count, start, dtype):
    """Elementwise envelope of the reference over the exp2 ULP perturbation."""
    runs = [reference_once(x, smooth, count, start, dtype, p)
            for p in (1.0 - EXP2_ULP, 1.0, 1.0 + EXP2_ULP)]
    qs = torch.stack([r[0].int() for r in runs])
    ss = torch.stack([r[1] for r in runs])
    return (qs.amin(0), qs.amax(0), ss.amin(0), ss.amax(0))


# ---------------------------------------------------------------------------
# One case
# ---------------------------------------------------------------------------
def run_case(stats, dtype_name, num_tokens, d, num_experts, pattern="random",
             layout="even", seed=20261111, use_wrapper=False, stream=False):
    """Check one shape. Diagnostics land in `stats` even when the case fails."""
    dtype = DTYPES[dtype_name]
    x_cpu, smooth_cpu = cpu_inputs(num_tokens, d, num_experts, dtype, pattern, seed)
    count_cpu, start_cpu, covered = expert_metadata(num_tokens, num_experts, layout)

    # Guards are sized in whole 64-byte units so the vector paths keep the
    # alignment they require while still exposing row-end overruns.
    x_guard, out_guard, scale_guard = 64, 64, 16
    xbase = torch.full((x_guard + x_cpu.numel() + x_guard,), 7.0, dtype=dtype)
    xbase[x_guard:x_guard + x_cpu.numel()] = x_cpu.flatten()
    xdev = xbase.cuda()
    x = xdev[x_guard:x_guard + x_cpu.numel()].view(num_tokens, 2 * d)

    smooth = smooth_cpu.cuda()
    count = count_cpu.cuda()
    start = start_cpu.cuda()

    work = torch.cuda.Stream() if stream else torch.cuda.current_stream()
    if stream:
        work.wait_stream(torch.cuda.current_stream())

    if use_wrapper:
        with torch.cuda.stream(work):
            out, scales = moe_swiglu_dynamic_quant_wrapper(x, smooth, count, start)
        outbase = scalebase = None
    else:
        outbase = torch.full((out_guard + num_tokens * d + out_guard,), 83,
                             dtype=torch.int8).cuda()
        out = outbase[out_guard:out_guard + num_tokens * d].view(num_tokens, d)
        scalebase = torch.full((scale_guard + num_tokens + scale_guard,), -11.0,
                               dtype=torch.float32).cuda()
        scales = scalebase[scale_guard:scale_guard + num_tokens]
        with torch.cuda.stream(work):
            aiter.moe_swiglu_dynamic_quant(x, smooth, count, start, out, scales, 1.0)
    torch.cuda.synchronize()

    assert torch.equal(xdev.cpu(), xbase), "input or its guard was modified"
    assert out.shape == (num_tokens, d) and out.dtype == torch.int8
    assert scales.shape == (num_tokens,) and scales.dtype == torch.float32
    if outbase is not None:
        raw = outbase.cpu()
        assert bool((raw[:out_guard] == 83).all()), "output head guard overwritten"
        assert bool((raw[out_guard + num_tokens * d:] == 83).all()), \
            "output tail guard overwritten"
        sg = scalebase.cpu()
        assert bool((sg[:scale_guard] == -11).all()), "scale head guard overwritten"
        assert bool((sg[scale_guard + num_tokens:] == -11).all()), \
            "scale tail guard overwritten"

    q_lo, q_hi, s_lo, s_hi = reference_band(x_cpu, smooth_cpu, count_cpu,
                                            start_cpu, dtype)
    dut_q = out.cpu().int()
    dut_s = scales.cpu()

    vec = vec_width(d)
    bad_q = (dut_q < q_lo) | (dut_q > q_hi)
    s_tol = 1e-6 * s_hi.clamp_min(1e-20)
    bad_s = (dut_s < s_lo - s_tol) | (dut_s > s_hi + s_tol)

    # Split the output mismatches by position inside the vector the kernel
    # stores. A failure confined to the odd lanes points at the int8 packing
    # rather than at the activation or the reduction.
    lanes = (bad_q.nonzero()[:, 1] % vec) if bool(bad_q.any()) else torch.empty(0)
    stats.update(
        covered_tokens=covered, grid_x=grid_x(num_tokens), branch=kernel_branch(d),
        vec=vec,
        ambiguous_outputs=int((q_lo != q_hi).sum()),
        ambiguous_scales=int((s_lo != s_hi).sum()),
        scales_ok=not bool(bad_s.any()),
        bad_outputs=int(bad_q.sum()), total_outputs=int(bad_q.numel()),
        bad_output_lanes=sorted({int(v) for v in lanes.tolist()}),
        output_sha256=hashlib.sha256(
            out.cpu().contiguous().view(torch.uint8).numpy().tobytes()).hexdigest(),
    )

    if bool(bad_q.any()):
        idx = tuple(bad_q.nonzero()[0].tolist())
        raise AssertionError(
            f"{int(bad_q.sum())}/{bad_q.numel()} output values outside the reference "
            f"band; offending lanes within each VEC={vec}: {stats['bad_output_lanes']}; "
            f"first {idx}: dut={int(dut_q[idx])} band=[{int(q_lo[idx])},{int(q_hi[idx])}]")

    if bool(bad_s.any()):
        i = int(bad_s.nonzero()[0])
        raise AssertionError(
            f"{int(bad_s.sum())} scales outside the reference band; first [{i}]: "
            f"dut={float(dut_s[i]):.9g} band=[{float(s_lo[i]):.9g},{float(s_hi[i]):.9g}]")

    return stats


# ---------------------------------------------------------------------------
# Rejection checks
# ---------------------------------------------------------------------------
def config_checks(records):
    x = torch.randn(4, 512, dtype=torch.bfloat16, device="cuda")
    smooth = torch.ones(2, 256, dtype=torch.float32, device="cuda")
    count = torch.tensor([2, 2], dtype=torch.int32, device="cuda")
    start = torch.tensor([0, 2], dtype=torch.int32, device="cuda")
    out = torch.empty(4, 256, dtype=torch.int8, device="cuda")
    scales = torch.empty(4, dtype=torch.float32, device="cuda")

    def call(**over):
        args = dict(scatter_tokens=x, smooth=smooth, experts_tokens_count=count,
                    experts_tokens_start=start, output=out, scales=scales, beta=1.0)
        args.update(over)
        aiter.moe_swiglu_dynamic_quant(**args)

    die_cases = [
        ("bad_mode", {"AITER_QUANT_DIE_MODE": "bad"}),
        ("zero_chunk", {"AITER_QUANT_DIE_MODE": "linear", "AITER_QUANT_DIE_CHUNK": "0"}),
        ("negative_chunk", {"AITER_QUANT_DIE_MODE": "linear", "AITER_QUANT_DIE_CHUNK": "-1"}),
        ("die_mask", {"AITER_QUANT_DIE_MODE": "linear", "AITER_QUANT_DIE_MASK": "1"}),
    ]
    for name, env in die_cases:
        prev = {k: os.environ.get(k) for k in env}
        os.environ.update(env)
        try:
            call()
            torch.cuda.synchronize()
        except (RuntimeError, ValueError) as exc:
            ok = "AITER_QUANT" in str(exc) or "linear launch requires" in str(exc)
            records.append(dict(id=name, status="PASS" if ok else "FAIL", error=str(exc)))
        else:
            records.append(dict(id=name, status="FAIL",
                                error="invalid launch configuration accepted"))
        finally:
            for k, v in prev.items():
                if v is None:
                    os.environ.pop(k, None)
                else:
                    os.environ[k] = v

    # d must be a multiple of the branch vector width, and the vectorized paths
    # stage expert metadata in a fixed 64-entry shared array.
    odd_d = torch.randn(4, 2 * 520, dtype=torch.bfloat16, device="cuda")
    many = MAX_EXPERTS + 1
    contract_cases = [
        ("odd_d", dict(scatter_tokens=odd_d,
                       smooth=torch.ones(2, 520, dtype=torch.float32, device="cuda"),
                       output=torch.empty(4, 520, dtype=torch.int8, device="cuda"))),
        ("too_many_experts", dict(
            smooth=torch.ones(many, 256, dtype=torch.float32, device="cuda"),
            experts_tokens_count=torch.ones(many, dtype=torch.int32, device="cuda"),
            experts_tokens_start=torch.zeros(many, dtype=torch.int32, device="cuda"))),
        ("odd_last_dim", dict(
            scatter_tokens=torch.randn(4, 511, dtype=torch.bfloat16, device="cuda"))),
        ("smooth_shape", dict(
            smooth=torch.ones(2, 128, dtype=torch.float32, device="cuda"))),
        ("smooth_dtype", dict(
            smooth=torch.ones(2, 256, dtype=torch.float16, device="cuda"))),
        ("metadata_dtype", dict(
            experts_tokens_count=torch.tensor([2, 2], dtype=torch.int64, device="cuda"))),
        ("metadata_length", dict(
            experts_tokens_start=torch.tensor([0], dtype=torch.int32, device="cuda"))),
        ("output_dtype", dict(
            output=torch.empty(4, 256, dtype=torch.float16, device="cuda"))),
        ("output_size", dict(
            output=torch.empty(2, 256, dtype=torch.int8, device="cuda"))),
        ("scales_size", dict(
            scales=torch.empty(2, dtype=torch.float32, device="cuda"))),
    ]
    for name, over in contract_cases:
        try:
            call(**over)
            torch.cuda.synchronize()
        except (RuntimeError, ValueError) as exc:
            records.append(dict(id=name, status="PASS", error=str(exc)))
        else:
            records.append(dict(id=name, status="FAIL",
                                error="unsupported parameters accepted"))

    # Zero tokens is a documented no-op, not an error.
    try:
        empty = torch.empty((0, 512), dtype=torch.bfloat16, device="cuda")
        aiter.moe_swiglu_dynamic_quant(
            empty, smooth, count, start,
            torch.empty((0, 256), dtype=torch.int8, device="cuda"),
            torch.empty((0,), dtype=torch.float32, device="cuda"), 1.0)
        torch.cuda.synchronize()
        records.append(dict(id="empty_tokens", status="PASS"))
    except Exception as exc:
        records.append(dict(id="empty_tokens", status="FAIL", error=str(exc)))


# ---------------------------------------------------------------------------
# Suites
# ---------------------------------------------------------------------------
def suite_cases(suite, dtype, max_d):
    """Yield (label, kwargs) pairs. Shapes stay small for the CPU perf model."""
    if suite == "quick":
        yield "m4d256e2", dict(num_tokens=4, d=256, num_experts=2)
        yield "m8d512e4", dict(num_tokens=8, d=512, num_experts=4)
        yield "m5d1024e1", dict(num_tokens=5, d=1024, num_experts=1)
        yield "m4d256e2_wrapper", dict(num_tokens=4, d=256, num_experts=2,
                                       use_wrapper=True)
        yield "m4d256e2_stream", dict(num_tokens=4, d=256, num_experts=2,
                                      stream=True)
    elif suite == "route":
        yield "m5d256e2", dict(num_tokens=5, d=256, num_experts=2)
    elif suite == "full":
        # One case per kernel branch, at the branch boundary.
        for d in (2, 256, 512, 1024, 2048, 4096, 8192, 16384, 32768, 32784):
            if d > max_d:
                continue
            yield f"m3d{d}e2", dict(num_tokens=3, d=d, num_experts=2)
    elif suite == "unassigned":
        yield "empty_tail", dict(num_tokens=8, d=256, num_experts=4,
                                 layout="empty_tail")
        yield "uncovered_tail", dict(num_tokens=8, d=256, num_experts=2,
                                     layout="uncovered_tail")
        yield "uncovered_tail_one_warp", dict(num_tokens=8, d=1024, num_experts=2,
                                              layout="uncovered_tail")
        yield "all_uncovered", dict(num_tokens=4, d=256, num_experts=1,
                                    layout="uncovered_tail")
    elif suite == "zero":
        yield "zero_rows", dict(num_tokens=4, d=256, num_experts=2, pattern="zero")
        yield "zero_rows_one_warp", dict(num_tokens=4, d=1024, num_experts=2,
                                         pattern="zero")
        yield "mixed_zero", dict(num_tokens=6, d=256, num_experts=2,
                                 pattern="mixed_zero")
        yield "saturate", dict(num_tokens=4, d=256, num_experts=2,
                               pattern="saturate")
    elif suite == "stride":
        # grid_x(1100) == 1024 < 1100, so blocks walk more than one row.
        yield "m1100d256e4", dict(num_tokens=1100, d=256, num_experts=4)
        yield "m1100d256e4_uncovered", dict(num_tokens=1100, d=256, num_experts=4,
                                            layout="uncovered_tail")
    elif suite != "config":
        raise ValueError(suite)


def main():
    p = argparse.ArgumentParser(description=__doc__)
    p.add_argument("--suite", default="quick",
                   choices=("quick", "full", "route", "unassigned", "zero",
                            "stride", "config"))
    p.add_argument("--die-mode", choices=("auto", "off", "linear"), default="auto")
    p.add_argument("--chunk", type=int, default=1)
    p.add_argument("--dtypes", nargs="+", choices=DTYPES, default=list(DTYPES))
    p.add_argument("--max-d", type=int, default=8192,
                   help="skip full-suite cases above this d (CPU perf model cost)")
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
    # The model is chosen before HIP init; the operator must not read it.
    os.environ.pop("GPU_CHIP", None)
    os.environ["AITER_QUANT_DIE_MODE"] = args.die_mode
    os.environ["AITER_QUANT_DIE_CHUNK"] = str(args.chunk)
    os.environ["AITER_QUANT_DIE_MASK"] = "0"
    os.environ["AITER_QUANT_LOG_LAUNCH"] = "1"

    records = []
    report = dict(arch=arch, topology=topo, aiter=aiter.__file__,
                  torch=torch.__version__, suite=args.suite, mode=args.die_mode,
                  chunk=args.chunk, exp2_ulp=EXP2_ULP, results=records)
    print(json.dumps({k: v for k, v in report.items() if k != "results"}), flush=True)

    for dtype in args.dtypes:
        for label, kwargs in suite_cases(args.suite, dtype, args.max_d):
            entry = dict(id=f"{dtype}_{label}", dtype=dtype, **{
                k: v for k, v in kwargs.items() if isinstance(v, (int, str))})
            started = time.monotonic()
            try:
                run_case(entry, dtype, **kwargs)
                entry["status"] = "PASS"
            except Exception as exc:
                entry.update(status="FAIL", error=f"{type(exc).__name__}: {exc}")
            entry["seconds"] = round(time.monotonic() - started, 3)
            records.append(entry)
            print(json.dumps(entry), flush=True)
            if args.json:
                args.json.parent.mkdir(parents=True, exist_ok=True)
                args.json.write_text(json.dumps(report, indent=2) + "\n")

    if args.suite == "config":
        config_checks(records)
        for record in records:
            print(json.dumps(record), flush=True)

    report["binaries"] = []
    for name, module in list(sys.modules.items()):
        filename = getattr(module, "__file__", "") or ""
        if name.endswith("module_quant") and filename.endswith(".so"):
            report["binaries"].append(dict(
                name=name, path=filename,
                sha256=hashlib.sha256(Path(filename).read_bytes()).hexdigest()))
    report["passed"] = sum(r["status"] == "PASS" for r in records)
    report["failed"] = len(records) - report["passed"]
    print(json.dumps({k: v for k, v in report.items() if k != "results"}), flush=True)
    if args.json:
        args.json.write_text(json.dumps(report, indent=2) + "\n")
    return bool(report["failed"])


if __name__ == "__main__":
    raise SystemExit(main())
