# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""RoPE 原生接口的 CPU 参考与单/多 die 正确性测试。

先按 README.md 配置环境。保存绝对路径，每次运行使用独立结果目录：
  test_py="$PWD/op_tests/gfx946_tests/rope/test_rope.py"
  GPU_CHIP=sb python "$test_py" --suite build --rebuild --json build.json
  GPU_CHIP=sb python "$test_py" --suite all --expect-xcds 1 --json single.json
  GPU_CHIP=sbx2 python "$test_py" --suite all --expect-xcds 2 --json dual.json
  GPU_CHIP=sbx2 python "$test_py" --suite route --die-mode linear --chunk 2 --expect-xcds 2 --json linear2.json

默认 quick。--list 无需 GPU；--case 可选择用例；--suite full 覆盖全部
26 个公开包装接口及布局/精度矩阵，all 再检查启动参数。gfx936/gfx938 使用
--require-arch 指定架构，不设置 --expect-xcds。off 只表示普通启动 API，
不能作为单 die 证据；需结合拓扑、CPU 参考与原始 completedWGs 判断。
本脚本不运行性能计时循环，Triton 接口见单独测试脚本。
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

ROOT = Path(__file__).resolve().parents[3]
MODULES = ("module_rope_general_fwd", "module_rope_general_bwd", "module_rope_pos_fwd")
FAMILIES = ("rope", "rope_2c", "rope_cached", "rope_cached_2c",
            "rope_cached_positions", "rope_cached_positions_2c",
            "rope_cached_positions_offsets", "rope_cached_positions_offsets_2c",
            "rope_thd", "rope_2d")
CASES = []
for family in FAMILIES:
    for operation in ("fwd", "fwd_inplace", "bwd"):
        if "positions" in family and operation == "bwd":
            continue
        api = family + "_" + operation
        CASES.append(dict(name=api, api=api, style=1, reuse=True, nope=False,
                          quick=api in ("rope_cached_2c_fwd_inplace", "rope_bwd", "rope_thd_fwd", "rope_2d_fwd", "rope_cached_positions_offsets_2c_fwd_inplace"),
                          route=api in ("rope_cached_2c_fwd_inplace", "rope_bwd", "rope_thd_fwd", "rope_2d_fwd", "rope_cached_positions_offsets_2c_fwd_inplace")))
for style in (0, 1):
    for reuse in (False, True):
        for nope in (False, True):
            for partial in (False, True):
                CASES.append(dict(name=f"cached2c_s{style}_r{int(reuse)}_n{int(nope)}_p{int(partial)}",
                                  api="rope_cached_2c_fwd_inplace", style=style, reuse=reuse,
                                  nope=nope, partial=partial, layout="d2" if partial else "sb"))
for api in ("rope_bwd", "rope_cached_2c_bwd", "rope_thd_bwd", "rope_2d_bwd",
            "rope_cached_positions_offsets_2c_fwd", "rope_2c_fwd"):
    for dtype in ("float32", "float16", "bfloat16"):
        CASES.append(dict(name=api + "_" + dtype, api=api, dtype=dtype,
                          freq_dtype=dtype, style=0, reuse=False, nope=True,
                          partial="2d" not in api, layout="d2", transpose=True))
CASES += [dict(name="heads16", api="rope_cached_2c_fwd_inplace", heads=16, style=0, reuse=True, nope=False),
          dict(name="single_token", api="rope_cached_2c_fwd_inplace", seq=1, style=1, reuse=True, nope=False, route=True),
          dict(name="empty", api="rope_cached_2c_fwd_inplace", seq=0, style=1, reuse=True, nope=False)]
for api in ("rope_fwd", "rope_2c_fwd", "rope_bwd", "rope_2c_bwd",
            "rope_cached_fwd", "rope_cached_2c_fwd", "rope_cached_bwd", "rope_cached_2c_bwd"):
    for style in (0, 1):
        CASES.append(dict(name=f"{api}_prefix_s{style}", api=api, style=style,
                          reuse=True, nope=True, partial=True, layout="d2"))


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
        name_status = hsa.hsa_agent_get_info(agent, 0, name)
        xcd_status = hsa.hsa_agent_get_info(agent, 0xA111, ctypes.byref(count))
        found.append(dict(name=name.value.decode(), xcds=count.value,
                          name_status=name_status, xcd_status=xcd_status))
        return 0
    assert hsa.hsa_init() == 0
    try:
        assert hsa.hsa_iterate_agents(visit, None) == 0
    finally:
        hsa.hsa_shut_down()
    return found


def rotate(x, cos, sin, style, reuse, nope):
    if reuse:
        cos = torch.cat((cos, cos), -1) if style == 0 else cos.repeat_interleave(2, -1)
        sin = torch.cat((sin, sin), -1) if style == 0 else sin.repeat_interleave(2, -1)
    width = cos.shape[-1]
    start = x.shape[-1] - width if nope else 0
    a = x[..., start:start + width]
    if style == 0:
        rotated = torch.cat((-a[..., width // 2:], a[..., :width // 2]), -1)
    else:
        pairs = a.reshape(*a.shape[:-1], width // 2, 2)
        rotated = torch.stack((-pairs[..., 1], pairs[..., 0]), -1).flatten(-2)
    return torch.cat((x[..., :start], a * cos + rotated * sin, x[..., start + width:]), -1)


def guarded(cpu, layout):
    shape = list(cpu.shape)
    if layout == "d2":
        shape[-1] *= 2
    elif layout == "sb":
        shape[0], shape[1] = shape[1], shape[0]
    size = 1
    for d in shape:
        size *= d
    base = torch.full((size + 64,), 17, dtype=cpu.dtype)
    view = base[32:-32].reshape(shape)
    view = view[..., ::2] if layout == "d2" else view.transpose(0, 1) if layout == "sb" else view
    view.copy_(cpu)
    device = base.cuda()
    result = device[32:-32].reshape(shape)
    result = result[..., ::2] if layout == "d2" else result.transpose(0, 1) if layout == "sb" else result
    return result, device, base, view


def numerical(c):
    api, style, reuse, nope = (c[k] for k in ("api", "style", "reuse", "nope"))
    dtype = getattr(torch, c.get("dtype", "float32"))
    fdtype = getattr(torch, c.get("freq_dtype", "float32"))
    s, b, h, d = c.get("seq", 3), 2, c.get("heads", 3), 16
    is_thd, is_2d, pair = "thd" in api, "2d" in api, "2c" in api
    inplace, backward = api.endswith("inplace"), api.endswith("bwd")
    shape = (6, h, d) if is_thd else (2, 6, h, d) if is_2d else (s, b, h, d)
    generator = torch.Generator().manual_seed(20261112)
    inputs = [torch.randn(shape, generator=generator).to(dtype)]
    if pair:
        inputs.append(torch.randn((s, b, 2, d), generator=generator).to(dtype))
    r = d // 2 if c.get("partial") or is_2d else d
    f = r // 2 if reuse else r
    count = 12 if "positions" in api else 3 if is_thd else s
    angles = torch.randn((count, 1, 1, f), generator=generator).to(fdtype)
    caches = [angles.float().cos().to(fdtype), angles.float().sin().to(fdtype)]
    positions = torch.tensor([[5, 1], [0, 7], [4, 2]], dtype=torch.int64)
    offsets = torch.tensor([[1, 2], [3, -1], [0, 4]], dtype=torch.int64)
    lens = torch.tensor([0, 2, 2, 5, 6], dtype=torch.int32)
    if is_2d:
        ah = torch.randn((1, 2, 1, f), generator=generator).to(fdtype)
        aw = torch.randn((1, 3, 1, f), generator=generator).to(fdtype)
        caches = [ah.float().cos().to(fdtype), ah.float().sin().to(fdtype),
                  aw.float().cos().to(fdtype), aw.float().sin().to(fdtype)]

    def reference(x):
        if is_2d:
            v = x.reshape(2, 2, 3, h, d)
            ch, sh, cw, sw = [v.double() for v in caches]
            a = rotate(v[..., :d // 2], ch.unsqueeze(2), sh.unsqueeze(2), style, reuse, nope)
            z = rotate(v[..., d // 2:], cw.unsqueeze(1), sw.unsqueeze(1), style, reuse, nope)
            return torch.cat((a, z), -1).reshape(x.shape)
        if is_thd:
            rows = []
            for begin, end in zip(lens[:-1], lens[1:]):
                a = angles[:end - begin, 0].double()
                rows.append(rotate(x[begin:end], a.cos(), a.sin(), style, reuse, nope))
            return torch.cat(rows, 0)
        if "cached" in api:
            cos, sin = [v.double() for v in caches]
            if "positions" in api:
                idx = positions + offsets if "offsets" in api else positions
                cos, sin = cos[:, 0, 0][idx].unsqueeze(2), sin[:, 0, 0][idx].unsqueeze(2)
        else:
            cos, sin = angles.double().cos(), angles.double().sin()
        return rotate(x, cos, sin, style, reuse, nope)

    expected = []
    for cpu in inputs:
        if backward:
            x = cpu.double().requires_grad_(True)
            expected.append(torch.autograd.grad(reference(x), x, cpu.double())[0])
        else:
            expected.append(reference(cpu.double()))
    layout = c.get("layout", "contiguous")
    buffers = [guarded(cpu, layout) for cpu in inputs]
    args = [v[0] for v in buffers]
    extra = [lens, angles] if is_thd else caches + [2, 3] if is_2d else caches if "cached" in api else [angles]
    if "positions" in api:
        extra += [positions]
        if "offsets" in api:
            extra += [offsets]
    gpu_extra = [v.cuda() if isinstance(v, torch.Tensor) else v for v in extra]
    keywords = dict(transpose_output=c.get("transpose", False)) if not (inplace or is_thd or is_2d) else {}
    print("DUT_BEGIN", c["name"], flush=True)
    out = getattr(rope, api)(*args, *gpu_extra, style, reuse, nope, **keywords)
    torch.cuda.synchronize()
    print("DUT_END", c["name"], flush=True)
    if inplace:
        assert out is None, "in-place wrapper return contract changed"
        actual = args
    else:
        actual = list(out) if pair else [out]
    errors, hashes = [], []
    tol = {torch.float32: (4e-6, 3e-6), torch.float16: (0.003, 0.002), torch.bfloat16: (0.025, 0.012)}[dtype]
    for result, ref, (view, base, original, cpu_view), cpu in zip(actual, expected, buffers, inputs):
        got = result.cpu()
        assert got.shape == cpu.shape and got.dtype == dtype
        torch.testing.assert_close(got.double(), ref, atol=tol[0], rtol=tol[1])
        if c.get("partial") and not is_2d:
            untouched = slice(0, d - r) if nope else slice(r, d)
            assert torch.equal(got[..., untouched], cpu[..., untouched]), "unrotated region modified"
        errors.append(float((got.double() - ref).abs().max()) if got.numel() else 0.0)
        hashes.append(hashlib.sha256(got.contiguous().view(torch.uint8).numpy().tobytes()).hexdigest())
        if inplace:
            cpu_view.copy_(got)
        assert torch.equal(base.cpu(), original), "input or guard storage modified"
        if keywords.get("transpose_output"):
            assert result.stride(0) == cpu.shape[2] * cpu.shape[3]
            assert result.stride(1) == cpu.shape[0] * result.stride(0)
    for dev, host in zip(gpu_extra, extra):
        if isinstance(host, torch.Tensor):
            assert torch.equal(dev.cpu(), host), "cache or index input modified"
    return c | dict(max_abs=errors, output_sha256=hashes, shape=list(shape))


def negative_checks(xcds):
    checks = []
    settings = [("MODE", "invalid")]
    if xcds >= 2:
        settings += [("CHUNK", "0"), ("CHUNK", "-1"), ("CHUNK", "bad"), ("MASK", "1")]
    else:
        settings += [("MODE", "linear")]
    keys = ["AITER_ROPE_DIE_" + x for x in ("MODE", "CHUNK", "MASK")]
    saved = {key: os.environ.get(key) for key in keys}
    try:
        x = torch.ones((2, 1, 1, 16), device="cuda")
        cos = torch.ones((2, 1, 1, 8), device="cuda")
        sin = torch.zeros_like(cos)
        for suffix, value in settings:
            os.environ.update(dict(zip(keys, ("linear" if xcds >= 2 else "auto", "1", "0"))))
            os.environ["AITER_ROPE_DIE_" + suffix] = value
            try:
                rope.rope_cached_fwd(x, cos, sin, 1, True, False)
            except (RuntimeError, ValueError) as error:
                assert "RoPE" in str(error) or "AITER_ROPE" in str(error), str(error)
                checks.append(dict(parameter=suffix, value=value, error=str(error)))
            else:
                raise AssertionError("invalid launch parameter accepted")
    finally:
        for key, value in saved.items():
            if value is None:
                os.environ.pop(key, None)
            else:
                os.environ[key] = value
    return checks


def main():
    ap = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    ap.add_argument("--suite", choices=("quick", "full", "route", "all", "build"), default="quick")
    ap.add_argument("--case", nargs="+")
    ap.add_argument("--list", action="store_true")
    ap.add_argument("--rebuild", action="store_true")
    ap.add_argument("--require-arch", default="gfx946")
    ap.add_argument("--expect-xcds", type=int)
    ap.add_argument("--die-mode", choices=("auto", "off", "linear"), default="auto")
    ap.add_argument("--chunk", type=int, default=1)
    ap.add_argument("--json", type=Path)
    args = ap.parse_args()
    if args.list:
        print(json.dumps(CASES, indent=2))
        return
    selected = CASES
    if args.case:
        assert set(args.case) <= {c["name"] for c in CASES}, "unknown case"
        selected = [c for c in CASES if c["name"] in args.case]
    elif args.suite in ("quick", "route"):
        selected = [c for c in CASES if c.get(args.suite)]
    for suffix, value in {"DIE_MODE": args.die_mode, "DIE_CHUNK": str(args.chunk), "DIE_MASK": "0", "LOG_LAUNCH": "1"}.items():
        os.environ["AITER_ROPE_" + suffix] = value
    sys.path.insert(0, str(ROOT))
    global torch, rope
    import torch
    import aiter
    import aiter.ops.rope as rope
    from aiter.jit import core
    torch.set_num_threads(1)
    assert Path(aiter.__file__).resolve().parent == ROOT / "aiter", aiter.__file__
    modules = {}
    for name in MODULES:
        module = None
        if not args.rebuild:
            try:
                module = core.get_module(name)
            except ModuleNotFoundError:
                pass
        if module is None:
            build = core.get_args_of_build(name) | dict(md_name=name)
            previous_rebuild = core.AITER_REBUILD
            try:
                if args.rebuild:
                    core.AITER_REBUILD = 1
                core.build_module(**{k: v for k, v in build.items() if k in inspect.signature(core.build_module).parameters})
            finally:
                core.AITER_REBUILD = previous_rebuild
            module = core.get_module(name)
            if name not in core.rebuilded_list:
                core.rebuilded_list.append(name)
        p = Path(module.__file__).resolve()
        modules[name] = dict(path=str(p), sha256=hashlib.sha256(p.read_bytes()).hexdigest())
    sources = ["aiter/jit/core.py", "aiter/jit/optCompilerConfig.json", "aiter/ops/rope.py",
               "csrc/include/hip_kernel_launch.h", "csrc/kernels/rope/rope_common.h",
               *[f"csrc/kernels/rope/{n}_kernels.cu" for n in ("general_fwd", "general_bwd", "pos_fwd")],
               *[f"csrc/pybind/rope_{n}_pybind.cu" for n in ("general_fwd", "general_bwd", "pos_fwd")],
               str(Path(__file__).resolve().relative_to(ROOT))]
    result = dict(status="RUNNING", aiter=aiter.__file__, torch=torch.__version__, hip=torch.version.hip,
                  args=vars(args) | dict(json=str(args.json)), modules=modules,
                  sources={p: hashlib.sha256((ROOT / p).read_bytes()).hexdigest() for p in sources}, numerical=[], negative=[])

    def save():
        if args.json:
            args.json.parent.mkdir(parents=True, exist_ok=True)
            args.json.write_text(json.dumps(result, indent=2) + "\n", encoding="utf-8")
    save()
    if args.suite != "build":
        torch.cuda.init()
        props = torch.cuda.get_device_properties(0)
        arch = props.gcnArchName.split(":")[0]
        assert arch == args.require_arch, arch
        agents = topology() if arch == "gfx946" else []
        xcds = 0
        if arch == "gfx946":
            assert torch.cuda.device_count() == 1 and len(agents) == 1, agents
            assert agents[0]["xcd_status"] == 0 and agents[0]["xcds"] > 0, agents
            xcds = agents[0]["xcds"]
        if args.expect_xcds is not None:
            assert xcds == args.expect_xcds, agents
        result.update(arch=arch, topology=agents, device=str(props), gpu_chip=os.environ.pop("GPU_CHIP", None))
        print("ENV", json.dumps(result), flush=True)
        save()
        for case in selected:
            result["numerical"].append(numerical(case))
            print("PASS", case["name"], flush=True)
            save()
        if args.suite == "all":
            result["negative"] = negative_checks(xcds)
    result["status"] = "PASS"
    save()
    print("SUMMARY", json.dumps(dict(status="PASS", numerical=len(result["numerical"]), negative=len(result["negative"]))), flush=True)


if __name__ == "__main__":
    main()
