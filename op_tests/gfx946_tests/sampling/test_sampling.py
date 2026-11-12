# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""两个采样接口的 CPU 参考、RNG、框架 ABI 与单/多 die 验证。

先按 README.md 配置容器环境，在仓库根目录保存脚本绝对路径；每次运行使用
独立结果目录，避免覆盖 m5out。GPU_CHIP 必须在 Python 启动前设置。
  test_py="$PWD/op_tests/gfx946_tests/sampling/test_sampling.py"
  GPU_CHIP=sb python "$test_py" --suite build --rebuild --json build.json
  GPU_CHIP=sb python "$test_py" --suite all --expect-xcds 1 --json single.json
  GPU_CHIP=sbx2 python "$test_py" --suite all --expect-xcds 2 --json dual.json
  GPU_CHIP=sbx2 python "$test_py" --suite route --expect-xcds 2 --die-mode linear --chunk 2 --json linear2.json

--ops top_p 或 joint 选择接口；--list 不初始化 GPU；--case 指定用例。
默认 quick；full 为数值矩阵；all 还包含 RNG、框架 ABI 和负向检查。
--die-mode off 是普通启动 API，不表示单 die。拓扑与数值 PASS 之外，须核对
原始 completedWGs 才能证明多个 XCD 实际执行。无预热或性能计时循环。
gfx936/gfx938 使用 --require-arch 指定架构，不设置 --expect-xcds。
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
PREFIX = "AITER_SAMPLING"
BASE_CASES = [
    dict(name="scalar", rows=5, vocab=64, quick=True, route=True),
    dict(name="indexed_arrays", rows=3, vocab=17, indexed=True, arrays=True),
    dict(name="tail1", rows=3, vocab=1),
    dict(name="tail2", rows=3, vocab=2),
    dict(name="tail3", rows=3, vocab=3),
    dict(name="tail17", rows=5, vocab=17),
    dict(name="tail4097", rows=3, vocab=4097),
    dict(name="ties", rows=5, vocab=17, ties=True),
    dict(name="greedy", rows=5, vocab=64, greedy=True),
    dict(name="disabled", rows=5, vocab=64, disabled=True),
    dict(name="nondeterministic", rows=5, vocab=64, deterministic=False, route=True),
    dict(name="batch64", rows=64, vocab=8, route=True),
    dict(name="fp16", rows=3, vocab=64, dtype="float16", api="python"),
    dict(name="bf16", rows=3, vocab=64, dtype="bfloat16", api="python"),
    dict(name="strided", rows=3, vocab=64, strided=True, api="python"),
    dict(name="empty", rows=0, vocab=17),
    dict(name="empty_indices", rows=3, vocab=17, empty_indices=True),
]
CASES = [dict(c, name=op + "_" + c["name"], op=op)
         for op in ("top_p", "joint") for c in BASE_CASES]


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


def digest(tensor):
    return hashlib.sha256(tensor.contiguous().view(torch.uint8).numpy().tobytes()).hexdigest()


def make_input(case):
    rows, vocab = case["rows"], case["vocab"]
    cpu = torch.zeros((rows, vocab), dtype=torch.float32)
    weights = [64, 48, 40, 32, 24, 20, 16, 12]
    for row in range(rows):
        if vocab < 8:
            cpu[row, (row + vocab - 1) % vocab] = 1
        else:
            positions = [(row * 7 + (vocab - 1) - j * max(1, vocab // 8)) % vocab for j in range(8)]
            assert len(set(positions)) == 8
            cpu[row, positions] = torch.tensor([32] * 8 if case.get("ties") else weights) / 256
    idx = torch.tensor([2, 0, 2, 1, 0], dtype=torch.int32) if case.get("indexed") else None
    if case.get("empty_indices"):
        idx = torch.empty(0, dtype=torch.int32)
    k = torch.tensor([1, 2, 4], dtype=torch.int32) if case.get("arrays") else 3
    p = torch.tensor([0.125, 0.5, 1.0]) if case.get("arrays") else 0.75
    if case.get("greedy"):
        k, p = 1, 0.001
    if case.get("disabled"):
        k, p = vocab, 1.0
    k = min(k, vocab) if isinstance(k, int) else k
    dtype = getattr(torch, case.get("dtype", "float32"))
    storage = torch.full((rows * vocab + 64,), 7.0, dtype=dtype)
    storage[32:-32] = cpu.flatten().to(dtype)
    backing = storage.cuda()
    probs = backing[32:-32].reshape(rows, vocab)
    if case.get("strided"):
        strided = torch.zeros((rows, vocab * 2), dtype=dtype)
        strided[:, ::2] = cpu.to(dtype)
        probs = strided.cuda()[:, ::2]
    return dict(cpu=cpu, probs=probs, backing=backing, original=storage,
                indices=idx.cuda() if idx is not None else None, cpu_indices=idx,
                k=k.cuda() if isinstance(k, torch.Tensor) else k,
                p=p.cuda() if isinstance(p, torch.Tensor) else p, cpu_k=k, cpu_p=p,
                batch=rows if idx is None else idx.numel())


def check_samples(data, samples, op):
    assert samples.shape == (data["batch"],) and samples.dtype == torch.int32
    vocab = data["cpu"].shape[1]
    assert ((samples >= 0) & (samples < vocab)).all(), "sample outside vocabulary"
    for b, token in enumerate(samples.tolist()):
        row = b if data["cpu_indices"] is None else int(data["cpu_indices"][b])
        probs = data["cpu"][row].double()
        selected = probs[token]
        assert selected > 0, "sample has zero probability"
        larger = probs > selected
        p = data["cpu_p"][row] if isinstance(data["cpu_p"], torch.Tensor) else data["cpu_p"]
        assert float(probs[larger].sum()) < float(p), "sample outside top-p set"
        if op == "joint":
            k = data["cpu_k"][row] if isinstance(data["cpu_k"], torch.Tensor) else data["cpu_k"]
            assert int(larger.sum()) < int(k), "sample outside top-k set"
    assert torch.equal(data["backing"].cpu(), data["original"]), "input/guards modified"


def native_call(op, data, output, deterministic=True, seed=946, offset=0):
    common = (data["probs"], output, data["indices"])
    parr = data["p"] if isinstance(data["p"], torch.Tensor) else None
    pval = 0.0 if parr is not None else float(data["p"])
    if op == "top_p":
        return module.top_p_sampling_from_probs(*common, parr, pval, deterministic, seed, offset)
    karr = data["k"] if isinstance(data["k"], torch.Tensor) else None
    kval = 0 if karr is not None else int(data["k"])
    return module.top_k_top_p_sampling_from_probs(*common, karr, kval, parr, pval,
                                                deterministic, seed, offset)


def public_call(op, data, **kwargs):
    kwargs["indices"] = data["indices"]
    if op == "top_p":
        return sampling.top_p_sampling_from_probs(data["probs"], data["p"], **kwargs)
    return sampling.top_k_top_p_sampling_from_probs(data["probs"], data["k"], data["p"], **kwargs)


def invoke(name, call):
    torch.cuda.synchronize()
    print("DUT_BEGIN", name, flush=True)
    value = call()
    torch.cuda.synchronize()
    print("DUT_END", name, flush=True)
    return value


def numerical(case):
    data = make_input(case)
    if case.get("api") == "python":
        samples = invoke(case["name"], lambda: public_call(case["op"], data, seed=946, offset=0)).cpu()
    else:
        guard = torch.full((data["batch"] + 64,), -777, dtype=torch.int32).cuda()
        output = guard[32:-32]
        invoke(case["name"], lambda: native_call(case["op"], data, output,
                                               case.get("deterministic", True)))
        cpu_guard = guard.cpu()
        assert (cpu_guard[:32] == -777).all() and (cpu_guard[-32:] == -777).all(), "output guard changed"
        samples = cpu_guard[32:-32]
    check_samples(data, samples, case["op"])
    return dict(name=case["name"], case=case, samples=samples.tolist(),
                input_sha256=digest(data["cpu"]), output_sha256=digest(samples), status="PASS")


def rng_checks(op):
    data = make_input(dict(rows=5, vocab=64, disabled=True))
    gen = torch.Generator(device="cuda").manual_seed(2026)
    before = gen.get_state().clone()
    outputs = []
    for label in ("fixed_a", "fixed_b"):
        out = invoke(op + "_" + label, lambda: public_call(op, data, seed=1234, offset=12, generator=gen)).cpu()
        check_samples(data, out, op)
        outputs.append(out)
    assert torch.equal(outputs[0], outputs[1]), "fixed RNG is not reproducible"
    assert torch.equal(before, gen.get_state()), "explicit RNG advanced generator"
    seeded = invoke(op + "_generator", lambda: public_call(op, data, generator=gen)).cpu()
    after = gen.get_state()
    seed, offset = before.view(torch.int64).tolist()
    step = data["batch"] * 32
    assert after.view(torch.int64).tolist() == [seed, offset + step]
    expected = invoke(op + "_generator_reference", lambda: public_call(op, data, seed=seed, offset=offset + step)).cpu()
    assert torch.equal(seeded, expected), "generator and explicit RNG disagree"
    second = invoke(op + "_generator_next", lambda: public_call(op, data, generator=gen)).cpu()
    assert gen.get_state().view(torch.int64).tolist() == [seed, offset + step * 2]
    for output in (seeded, expected, second):
        check_samples(data, output, op)
    return dict(op=op, status="PASS", checks=4, fixed=outputs[0].tolist(),
                generator_first=seeded.tolist(), generator_second=second.tolist(),
                generator_state_before=[seed, offset], generator_state_after=[seed, offset + step * 2])


def framework_check(op, arrays):
    data = make_input(dict(rows=3 if arrays else 5, vocab=17 if arrays else 64,
                           arrays=arrays, indexed=arrays))
    torch.cuda.manual_seed(2026)
    gen = torch.cuda.default_generators[0]
    seed, offset = gen.get_state().view(torch.int64).tolist()
    p = data["p"]
    k = data["k"]
    args = [data["probs"], data["indices"]]
    if op == "joint":
        args += [k if arrays else None, 0 if arrays else k]
    args += [p if arrays else None, 0.0 if arrays else p]
    name = "top_p_sampling_from_probs" if op == "top_p" else "top_k_top_p_sampling_from_probs"
    function = getattr(torch.ops.aiter, name)
    label = op + ("_framework_arrays" if arrays else "_framework_scalar")
    got = invoke(label, lambda: function(*args, deterministic=True)).cpu()
    expected = invoke(label + "_reference", lambda: public_call(
        op, data, seed=seed, offset=offset + data["batch"] * 32)).cpu()
    assert torch.equal(got, expected), "framework ABI differs from Python API"
    assert gen.get_state().view(torch.int64).tolist() == [seed, offset + data["batch"] * 32]
    check_samples(data, got, op)
    meta_args = [x.to("meta") if isinstance(x, torch.Tensor) else x for x in args]
    meta = function(*meta_args)
    assert meta.device.type == "meta" and meta.shape == got.shape and meta.dtype == got.dtype
    return dict(name=label, status="PASS", samples=got.tolist(), schema=str(function.default._schema))


def reject(name, call, expected):
    try:
        call()
    except (RuntimeError, ValueError) as error:
        assert expected in str(error), (name, str(error))
    else:
        raise AssertionError("accepted invalid input: " + name)
    print("PASS reject", name, flush=True)
    return dict(name=name, status="PASS", expected=expected)


def negative_checks(op, xcds):
    data = make_input(dict(rows=5, vocab=64))
    output = torch.empty(5, dtype=torch.int32, device="cuda")
    checks = []
    for name, changes, out, expected in [
        ("probs_dtype", dict(probs=data["probs"].half()), output, "probs must"),
        ("probs_rank", dict(probs=data["probs"].flatten()), output, "probs must"),
        ("probs_cpu", dict(probs=data["cpu"]), output, "probs must"),
        ("probs_stride", dict(probs=data["probs"][:, ::2]), output, "probs must"),
        ("output_dtype", {}, output.long(), "output must"),
        ("output_length", {}, output[:4], "output length"),
        ("indices_dtype", dict(indices=torch.arange(5, device="cuda", dtype=torch.int64)), output, "indices must"),
        ("indices_length", dict(indices=torch.arange(4, device="cuda", dtype=torch.int32)), output, "indices must"),
        ("p_length", dict(p=torch.ones(4, device="cuda")), output, "top_p must"),
        ("p_dtype", dict(p=torch.ones(5, device="cuda", dtype=torch.float16)), output, "top_p must"),
        ("p_zero", dict(p=0.0), output, "top_p must"),
        ("p_nan", dict(p=float("nan")), output, "top_p must"),
        ("p_underflow", dict(p=1e-100), output, "top_p must"),
        ("empty_vocab", dict(probs=torch.empty(5, 0, device="cuda")), output, "nonempty vocabulary"),
    ]:
        checks.append(reject(op + "_" + name, lambda: native_call(op, data | changes, out), expected))
    if op == "joint":
        for name, k in [("k_zero", 0), ("k_overflow", 2**31), ("k_length", torch.ones(4, device="cuda", dtype=torch.int32))]:
            checks.append(reject(op + "_" + name, lambda: native_call(op, data | dict(k=k), output), "top_k must"))
        checks.append(reject("filter_order", lambda: public_call(op, data, filter_apply_order="top_k_first"), "Only filter_apply_order"))
    nan_probs = data["probs"].clone()
    nan_probs[0, 0] = float("nan")
    checks.append(reject(op + "_check_nan", lambda: public_call(op, data | dict(probs=nan_probs), check_nan=True), "contains NaN"))
    keys = [PREFIX + suffix for suffix in ("_DIE_MODE", "_DIE_CHUNK", "_DIE_MASK")]
    saved = {key: os.environ.get(key) for key in keys}
    try:
        os.environ[keys[0]] = "invalid"
        checks.append(reject(op + "_mode", lambda: native_call(op, data, output), "must be auto, off or linear"))
        os.environ[keys[0]] = "linear"
        if xcds < 2:
            checks.append(reject(op + "_linear_single", lambda: native_call(op, data, output), "linear launch requires"))
        else:
            for value in ("0", "-1", "abc", "4294967296"):
                os.environ[keys[1]] = value
                checks.append(reject(op + "_chunk_" + value, lambda: native_call(op, data, output), keys[1]))
            os.environ[keys[1]] = "1"
            for value in ("1", "-1", "abc"):
                os.environ[keys[2]] = value
                checks.append(reject(op + "_mask_" + value, lambda: native_call(op, data, output), keys[2]))
    finally:
        for key, value in saved.items():
            if value is None:
                os.environ.pop(key, None)
            else:
                os.environ[key] = value
    return checks


def main():
    ap = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    ap.add_argument("--suite", choices=("quick", "full", "route", "rng", "negative", "all", "build"), default="quick")
    ap.add_argument("--ops", nargs="+", choices=("top_p", "joint"), default=["top_p", "joint"])
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
    selected = [c for c in CASES if c["op"] in args.ops]
    if args.case:
        assert set(args.case) <= {c["name"] for c in selected}, "unknown case"
        selected = [c for c in selected if c["name"] in args.case]
    elif args.suite in ("quick", "route"):
        selected = [c for c in selected if c.get(args.suite)]
    assert selected
    for suffix, value in {"_DIE_MODE": args.die_mode, "_DIE_CHUNK": str(args.chunk),
                          "_DIE_MASK": "0", "_LOG_LAUNCH": "1"}.items():
        os.environ[PREFIX + suffix] = value
    sys.path.insert(0, str(ROOT))
    global torch, sampling, module
    import torch
    import aiter
    import aiter.ops.sampling as sampling
    from aiter.jit import core
    torch.set_num_threads(1)
    assert Path(aiter.__file__).resolve().parent == ROOT / "aiter", aiter.__file__
    module = None
    if not args.rebuild:
        try:
            module = core.get_module("module_sampling")
        except ModuleNotFoundError:
            pass
    if module is None:
        build = core.get_args_of_build("module_sampling") | dict(md_name="module_sampling")
        core.build_module(**{k: v for k, v in build.items() if k in inspect.signature(core.build_module).parameters})
        module = core.get_module("module_sampling")
        if "module_sampling" not in core.rebuilded_list:
            core.rebuilded_list.append("module_sampling")
    so = Path(module.__file__).resolve()
    sources = ["aiter/ops/sampling.py", "aiter/jit/core.py", "aiter/jit/optCompilerConfig.json",
               "csrc/kernels/sampling.cu", "csrc/include/hip_kernel_launch.h", "csrc/include/sampling.h",
               "csrc/include/rocm_ops.hpp", "csrc/pybind/sampling_pybind.cu",
               str(Path(__file__).resolve().relative_to(ROOT))]
    result = dict(status="RUNNING", aiter=aiter.__file__, torch=torch.__version__, hip=torch.version.hip,
                  args=vars(args) | dict(json=str(args.json)), module=str(so),
                  module_sha256=hashlib.sha256(so.read_bytes()).hexdigest(),
                  sources={p: hashlib.sha256((ROOT / p).read_bytes()).hexdigest() for p in sources},
                  numerical=[], rng=[], framework=[], negative=[])

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
        if args.suite in ("quick", "full", "route", "all"):
            for case in selected:
                result["numerical"].append(numerical(case))
                print("PASS", case["name"], flush=True)
                save()
        if args.suite in ("rng", "all"):
            for op in args.ops:
                result["rng"].append(rng_checks(op))
                for arrays in (False, True):
                    result["framework"].append(framework_check(op, arrays))
                save()
        if args.suite in ("negative", "all"):
            for op in args.ops:
                result["negative"].extend(negative_checks(op, xcds))
                save()
    result["status"] = "PASS"
    save()
    print("SUMMARY", json.dumps({k: len(result[k]) for k in ("numerical", "rng", "framework", "negative")}
                                | dict(status="PASS", module_sha256=result["module_sha256"])), flush=True)


if __name__ == "__main__":
    main()
