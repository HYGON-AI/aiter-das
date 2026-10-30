# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# 四个接口：dynamic_per_tensor_quant、dynamic_per_token_scaled_quant、
# per_token_quant_hip、static_per_tensor_quant。测试只依赖已安装的 AITER、
# Torch 和标准库；每例与 CPU 参考比较，预分配缓冲区另检查输出及 scale 保护区。
#
# 在 bmz-perf_model 的 zxw_model_8585 容器中，先编译 gfx946 的
# module_quant 和 module_cpp_api，并确认使用的是预期的 AITER 源码和缓存：
#   cd /wksp/dcu-das/aiter
#   export GPU_ARCHS=gfx946 PMD_PATH=/opt/rocm/pmd
#   export LD_LIBRARY_PATH=/opt/rocm/lib:/opt/rocm/pmd:${LD_LIBRARY_PATH:-}
#   unset AITER_JIT_DIR PYTHONPATH AITER_REBUILD
#
# 单 die（PMD 单 XCD）：四个接口的快速数值检查，每个 dtype 8 例：
#   export GPU_CHIP=sb
#   python op_tests/gfx946_tests/quant/test_quant.py --suite quick --dtypes bf16 --expect-xcds 1
#   python op_tests/gfx946_tests/quant/test_quant.py --suite quick --dtypes fp16 --expect-xcds 1
#
# 多 die（PMD 双 XCD）：四个接口的快速数值检查，以及显式 linear 分发：
#   export GPU_CHIP=sbx2
#   python op_tests/gfx946_tests/quant/test_quant.py --suite quick --dtypes bf16 --expect-xcds 2
#   python op_tests/gfx946_tests/quant/test_quant.py --suite quick --dtypes fp16 --expect-xcds 2
#   python op_tests/gfx946_tests/quant/test_quant.py --suite route --dtypes bf16 --qtypes int8 --die-mode linear --chunk 1 --expect-xcds 2
#   python op_tests/gfx946_tests/quant/test_quant.py --suite route --dtypes bf16 --qtypes int8 --die-mode linear --chunk 2 --expect-xcds 2
#   python op_tests/gfx946_tests/quant/test_quant.py --suite config --expect-xcds 2
#
# 完整数值矩阵建议按接口和 dtype 拆进程，避免 PMD 长时间模拟或 signal 耗尽。
# 将 GPU_CHIP 和 xcd 分别设置为 sb/1 或 sbx2/2，执行：
#   for op in dynamic_per_tensor_quant dynamic_per_token_scaled_quant per_token_quant_hip static_per_tensor_quant; do
#     for dtype in bf16 fp16; do
#       for qtype in int8 fp8; do
#         python op_tests/gfx946_tests/quant/test_quant.py --suite full --ops "$op" --dtypes "$dtype" --qtypes "$qtype" --expect-xcds "$xcd"
#       done
#     done
#   done
# 可将 full 换成 boundaries、prefix 或 zero_short；后两项只针对逐 token 接口。
# 例如在单 die 运行前设置 export GPU_CHIP=sb; xcd=1，在双 die 则设置
# export GPU_CHIP=sbx2; xcd=2。模型选择必须在 Python/HIP 初始化前完成。
#
# --die-mode 默认为 auto，依据 HIP 报告的 numXcc 选择普通或多 die 启动；
# off 使用普通启动，并不证明只使用一个 XCD。--non-default-stream 可单独
# 检查非默认 stream；--json 只写可选结果文件。数值通过及启动日志不能单独
# 证明两个 XCD 都执行了 TG，需另外查看 PMD 每个 dispatch 的 completedWGs。
# 真实 gfx946 使用实际设备拓扑，不需要设置 GPU_CHIP；PMD 不是性能基准。
"""Small, CPU-reference checks of the four public quantization APIs."""
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

OPS = ("dynamic_per_tensor_quant", "static_per_tensor_quant",
       "dynamic_per_token_scaled_quant", "per_token_quant_hip")
DTYPES = {"fp16": torch.float16, "bf16": torch.bfloat16}
QTYPES = {"int8": torch.int8, "fp8": torch.float8_e4m3fn}


def topology():
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


def cpu_input(m, n, dtype, pattern):
    g = torch.Generator().manual_seed(20261028 + n)
    x = torch.randn(m, n, generator=g) * (torch.arange(m).float()[:, None] + 1) * 0.2
    if pattern == "mixed_zero":
        x[0] = 0
    elif pattern == "zero":
        x.zero_()
    elif pattern == "saturate":
        x = torch.tensor([-1000., -128.5, -127.5, -2.5, -1.5, 0., 1.5, 2.5,
                          126.5, 127.5, 128.5, 1000.]).repeat((m*n+11)//12)[:m*n].reshape(m, n)
    return x.to(dtype)


def run_case(op, dtype_name, quant_name, m, n, pattern="random", offset=0,
             prefix=None, factor=1, three_d=False, stream=False):
    dtype, qdtype = DTYPES[dtype_name], QTYPES[quant_name]
    cpu = cpu_input(m, n, dtype, pattern)
    shape = (1, m, n) if three_d else (m, n)
    cpu = cpu.reshape(shape)
    # Guarded allocations expose row-end writes and unaligned contiguous views.
    guard = 32 + offset
    xbase = torch.full((guard + cpu.numel() + 32,), 99., dtype=dtype)
    xbase[guard:guard+cpu.numel()] = cpu.flatten()
    device_base = xbase.cuda()
    x = device_base[guard:guard+cpu.numel()].view(shape)
    outbase = torch.full((guard+cpu.numel()+32,), 83, dtype=torch.uint8).cuda()
    out = outbase[guard:guard+cpu.numel()].view(qdtype).view(shape)
    per_tensor = "per_tensor" in op
    ns = 1 if per_tensor else m
    scale_cpu = torch.full((ns+2,), -11., dtype=torch.float32)
    if op == "static_per_tensor_quant":
        scale_cpu[1] = 1. if pattern == "saturate" else 0.013
    scale_base = scale_cpu.cuda()
    scale = scale_base[1:-1].view((1,) if per_tensor else (*shape[:-1], 1))
    kwargs = {}
    if prefix is not None:
        kwargs = dict(num_rows=torch.tensor([prefix], dtype=torch.int32).cuda(), num_rows_factor=factor)
    active = m if prefix is None else min(m, prefix*factor)
    work_stream = torch.cuda.Stream() if stream else torch.cuda.current_stream()
    work_stream.wait_stream(torch.cuda.current_stream())
    with torch.cuda.stream(work_stream):
        if op == "per_token_quant_hip":
            out, scale = aiter.per_token_quant_hip(x, quant_dtype=qdtype, **kwargs)
        elif per_tensor:
            getattr(aiter, op)(out, x, scale)
        else:
            aiter.dynamic_per_token_scaled_quant(out, x, scale, **kwargs)
    torch.cuda.synchronize()
    assert torch.equal(device_base.cpu(), xbase), "input/guard modified"
    assert out.shape == cpu.shape and out.dtype == qdtype
    assert scale.dtype == torch.float32
    if op != "per_token_quant_hip":
        raw = outbase.cpu()
        assert bool((raw[:guard] == 83).all() and (raw[guard+cpu.numel():] == 83).all()), "output guard overwritten"
        sb = scale_base.cpu()
        assert sb[0] == -11 and sb[-1] == -11, "scale guard overwritten"
        if active < m:
            assert bool((raw[guard+active*n:guard+m*n] == 83).all()), "inactive output overwritten"
            assert bool((sb[1+active:-1] == -11).all()), "inactive scale overwritten"
    else:
        assert scale.shape == (*shape[:-1], 1)
    if active == 0:
        return dict(max_scale_error=0., active_rows=0)
    values = cpu.float().view(m, n)[:active]
    limit = 127. if quant_name == "int8" else 448.
    if per_tensor:
        if op == "static_per_tensor_quant":
            expected_scale = scale_cpu[1:2]
        else:
            amax = values.abs().max()
            expected_scale = (amax / limit if amax > 0 else torch.tensor(1.)).reshape(1)
        multiplier = 1. / expected_scale
    else:
        amax = values.abs().amax(-1, keepdim=True)
        # Existing public paths use an epsilon floor for INT8 and group rows.
        if quant_name == "int8" or n in (32, 64, 128):
            amax = amax.clamp_min(1e-10)
        # gfx938 的对齐向量路径与当前 Torch CPU 参考采用的 FP32 计算顺序不同：
        # INT8 kernel 直接计算 127/amax，而 Torch 的“标量/张量”会先求倒数再乘；
        # FP8 kernel 先计算 amax*float32(1/448)，再求倒数，而参考原先先做除法。
        # 数学公式相同，但中间结果可能相差少量 ULP，使接近量化中点的数据落在
        # 两侧；CPU 与 gfx938 在相同中点的最终取偶舍入实测一致。
        # 此处仅对实际命中的 gfx938 向量路径按其计算顺序构造 CPU 参考；
        # 奇数尾部或错位地址走安全路径，gfx946 也有自己的计算顺序，均保留
        # 原参考。scale 仍单独校验，量化输出仍逐元素精确比较，不放宽容差。
        arch = torch.cuda.get_device_properties(x.device).gcnArchName.split(":")[0]
        vec_width = 8 if n <= 2048 else 16 if n <= 4096 or n > 8192 else 32
        gfx938_vector = (arch == "gfx938" and n % vec_width == 0 and
                         x.data_ptr() % 16 == 0 and out.data_ptr() % 16 == 0)
        expected_scale = (amax * (1.0 / limit) if gfx938_vector else amax / limit)
        expected_scale = torch.where(expected_scale == 0, torch.ones_like(expected_scale), expected_scale)
        if gfx938_vector:
            multiplier = (torch.full_like(amax, limit) / amax if quant_name == "int8"
                          else torch.ones_like(expected_scale) / expected_scale)
        else:
            multiplier = limit / amax if quant_name == "int8" else 1. / expected_scale
    actual_scale = scale.cpu().reshape(-1)[:1 if per_tensor else active]
    torch.testing.assert_close(actual_scale, expected_scale.reshape(-1), rtol=2e-6, atol=1e-14)
    normalized = values * multiplier
    expected = normalized.round().clamp(-128, 127).to(qdtype) if quant_name == "int8" else normalized.clamp(-448,448).to(qdtype)
    actual = out.cpu().view(m, n)[:active]
    output_hash = hashlib.sha256(bytes(actual.contiguous().view(torch.uint8).flatten().tolist())).hexdigest()
    scale_hash = hashlib.sha256(bytes(actual_scale.contiguous().view(torch.uint8).flatten().tolist())).hexdigest()
    # No mismatch-percentage tolerance: every element must match the CPU reference.
    if not torch.equal(actual.float(), expected.float()):
        bad = actual.float() != expected.float()
        idx = tuple(bad.nonzero()[0].tolist())
        raise AssertionError(f"{int(bad.sum())} output mismatches; first {idx}: {actual.float()[idx]} vs {expected.float()[idx]}; output_sha256={output_hash}; scale_sha256={scale_hash}")
    return dict(max_scale_error=float((actual_scale-expected_scale.reshape(-1)).abs().max()),
                active_rows=active, output_sha256=output_hash, scale_sha256=scale_hash)


def main():
    p = argparse.ArgumentParser(description=__doc__)
    p.add_argument("--suite", choices=("quick", "full", "route", "boundaries", "wave", "prefix", "zero_short", "config"), default="quick")
    p.add_argument("--die-mode", choices=("auto", "off", "linear"), default="auto")
    p.add_argument("--chunk", type=int, default=1)
    p.add_argument("--non-default-stream", action="store_true")
    p.add_argument("--require-arch", default="gfx946")
    p.add_argument("--expect-xcds", type=int)
    p.add_argument("--ops", nargs="+", choices=OPS, default=list(OPS))
    p.add_argument("--dtypes", nargs="+", choices=DTYPES, default=list(DTYPES))
    p.add_argument("--qtypes", nargs="+", choices=QTYPES, default=list(QTYPES))
    p.add_argument("--json", type=Path)
    args = p.parse_args()
    torch.cuda.init()
    arch = torch.cuda.get_device_properties(0).gcnArchName.split(":")[0]
    assert arch == args.require_arch, (arch, args.require_arch)
    topo = topology()
    if args.expect_xcds:
        assert any(t["xcds"] == args.expect_xcds and t["status"] == 0 for t in topo), topo
    os.environ.pop("GPU_CHIP", None)
    os.environ["AITER_QUANT_DIE_MODE"] = args.die_mode
    os.environ["AITER_QUANT_DIE_CHUNK"] = str(args.chunk)
    os.environ["AITER_QUANT_DIE_MASK"] = "0"
    os.environ["AITER_QUANT_LOG_LAUNCH"] = "1"
    records = []
    report = dict(arch=arch, topology=topo, aiter=aiter.__file__, torch=torch.__version__,
                  suite=args.suite, mode=args.die_mode, chunk=args.chunk, results=records)
    print(json.dumps({k:v for k,v in report.items() if k != "results"}), flush=True)
    for op in args.ops:
        for dtype in args.dtypes:
            for quant in args.qtypes:
                cases = [(3, 256, "random", 0)]
                if args.suite == "config":
                    continue
                if args.suite == "route":
                    cases = [(5, 256, "random", 0)]
                elif args.suite == "full":
                    cases = [(3,n,"mixed_zero" if n == 256 else "random",0) for n in (32,64,128,256,2048,4096,8192,8208)]
                elif args.suite == "boundaries":
                    cases = [(3,n,"random",offset) for n,offset in ((1,0),(7,0),(33,0),(257,0),(256,1))]
                    cases += [(3,256,"zero",0)]
                    if op == "static_per_tensor_quant":
                        cases += [(3,256,"saturate",0)]
                elif args.suite == "wave":
                    if dtype != "bf16" or quant != "int8" or "per_tensor" in op:
                        continue
                    cases = [(513,640,"random",0)]
                elif args.suite == "prefix":
                    if "per_tensor" in op:
                        continue
                    cases = [(5,n,"random",0) for n in (32,128,256,257,8208)]
                elif args.suite == "zero_short":
                    if "per_tensor" in op:
                        continue
                    cases = [(3,n,"zero",0) for n in (32,64,128)]
                for m,n,pattern,offset in cases:
                    name = f"{op}_{dtype}_{quant}_m{m}n{n}_{pattern}_off{offset}"
                    entry = dict(id=name, m=m, n=n, dtype=dtype, quant=quant, op=op)
                    started = time.monotonic()
                    try:
                        entry.update(run_case(op,dtype,quant,m,n,pattern,offset,
                                              prefix=(1 if args.suite=="prefix" else None),factor=2,
                                              three_d=(op=="per_token_quant_hip"),
                                              stream=args.non_default_stream))
                        entry["status"] = "PASS"
                    except Exception as exc:
                        entry.update(status="FAIL", error=str(exc))
                    entry["seconds"] = time.monotonic()-started
                    records.append(entry)
                    print(json.dumps(entry), flush=True)
                    if args.json:
                        args.json.parent.mkdir(parents=True,exist_ok=True)
                        args.json.write_text(json.dumps(report,indent=2)+"\n")
    if args.suite == "config":
        x = torch.ones(3,256,dtype=torch.bfloat16).cuda()
        y = torch.empty_like(x,dtype=torch.int8)
        scale = torch.empty(3,1,device="cuda")
        tests = [
            ("bad_mode",{"AITER_QUANT_DIE_MODE":"bad"}),
            ("zero_chunk",{"AITER_QUANT_DIE_MODE":"linear","AITER_QUANT_DIE_CHUNK":"0"}),
            ("negative_chunk",{"AITER_QUANT_DIE_MODE":"linear","AITER_QUANT_DIE_CHUNK":"-1"}),
            ("die_mask",{"AITER_QUANT_DIE_MODE":"linear","AITER_QUANT_DIE_MASK":"1"}),
        ]
        for name,env in tests:
            prev = {k:os.environ.get(k) for k in env}
            os.environ.update(env)
            try:
                aiter.dynamic_per_token_scaled_quant(y,x,scale)
            except (RuntimeError,ValueError) as exc:
                status = "PASS" if ("AITER_QUANT" in str(exc) or "linear launch requires" in str(exc)) else "FAIL"
                records.append(dict(id=name,status=status,error=str(exc)))
            else:
                records.append(dict(id=name,status="FAIL",error="invalid launch config accepted"))
            finally:
                for key,value in prev.items():
                    if value is None:
                        os.environ.pop(key,None)
                    else:
                        os.environ[key]=value
        for name,xx,yy,ss,kw in [
            ("bad_output_size",x,y[:1],scale,{}),
            ("bad_scale_size",x,y,scale[:1],{}),
            ("bad_input_dtype",x.float(),y,scale,{}),
            ("cpu_scale",x,y,scale.cpu(),{}),
            ("cpu_num_rows",x,y,scale,dict(num_rows=torch.tensor([1],dtype=torch.int32))),
            ("zero_factor",x,y,scale,dict(num_rows_factor=0)),
        ]:
            try:
                aiter.dynamic_per_token_scaled_quant(yy,xx,ss,**kw)
            except (RuntimeError,ValueError) as exc:
                records.append(dict(id=name,status="PASS",error=str(exc)))
            else:
                records.append(dict(id=name,status="FAIL",error="invalid tensor accepted"))
        empty = torch.empty((0, 32), dtype=torch.bfloat16, device="cuda")
        empty_out = torch.empty_like(empty, dtype=torch.int8)
        empty_scales = torch.empty((0, 1), dtype=torch.float32, device="cuda")
        scalar = torch.ones((1,), dtype=torch.float32, device="cuda")
        for name in OPS:
            try:
                if name == "static_per_tensor_quant":
                    aiter.static_per_tensor_quant(empty_out, empty, scalar)
                elif name == "dynamic_per_tensor_quant":
                    aiter.dynamic_per_tensor_quant(empty_out, empty, scalar)
                elif name == "dynamic_per_token_scaled_quant":
                    aiter.dynamic_per_token_scaled_quant(empty_out, empty, empty_scales)
                else:
                    result, scales = aiter.per_token_quant_hip(empty)
                    assert result.shape == empty.shape and scales.shape == (0,1)
                torch.cuda.synchronize()
                if name == "dynamic_per_tensor_quant":
                    assert scalar.cpu().item() == 1.0
                records.append(dict(id="empty_"+name,status="PASS"))
            except Exception as exc:
                records.append(dict(id="empty_"+name,status="FAIL",error=str(exc)))
        for record in records:
            print(json.dumps(record),flush=True)
    report["binaries"] = []
    for name,module in list(sys.modules.items()):
        filename = getattr(module,"__file__","") or ""
        if name.endswith(("module_quant","module_cpp_api")) and filename.endswith(".so"):
            report["binaries"].append(dict(name=name,path=filename,sha256=hashlib.sha256(Path(filename).read_bytes()).hexdigest()))
    report["passed"] = sum(r["status"]=="PASS" for r in records)
    report["failed"] = len(records)-report["passed"]
    print(json.dumps({k:v for k,v in report.items() if k != "results"}),flush=True)
    if args.json:
        args.json.write_text(json.dumps(report,indent=2)+"\n")
    return bool(report["failed"])


if __name__ == "__main__":
    raise SystemExit(main())
