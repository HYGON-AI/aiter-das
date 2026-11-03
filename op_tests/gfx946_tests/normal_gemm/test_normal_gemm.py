#!/usr/bin/env python3
"""Self-contained normal GEMM correctness and timing harness.

Run from an installed AITER checkout; no generated input or helper is required:
  python op_tests/gfx946_tests/normal_gemm/test_normal_gemm.py --op wvSpltK --case m1_n9_k512
  python op_tests/gfx946_tests/normal_gemm/test_normal_gemm.py --op mm --suite full
PMD (set before HIP initialization):
  GPU_ARCHS=gfx946 GPU_CHIP=sbx2 PMD_PATH=/opt/rocm/pmd \
  LD_LIBRARY_PATH=/opt/rocm/lib:/opt/rocm/pmd \
  python op_tests/gfx946_tests/normal_gemm/test_normal_gemm.py --op wvSpltK --expect-xcds 2
Default: no warmup, one DUT call. Use --warmup 3 --repeat 20 on physical GPUs.
FP32 CPU reference is computed from the exact quantized inputs. Output files
are optional evidence, never dependencies. M is activation rows, N output width.
"""
import argparse
import ctypes
import hashlib
import json
import os
from pathlib import Path
import sys


def matrix():
    return [dict(name=f"m{m}_n{n}_k{k}", m=m, n=n, k=k) for m, n, k in
            [(1, 9, 512), (2, 64, 512), (4, 257, 1024), (4, 512, 2048)]]


def boundaries():
    return [dict(name=f"m{m}_n{n}_k{k}", m=m, n=n, k=k) for m, n, k in
            [(1, 1, 512), (3, 17, 1536), (4, 9, 8704), (2, 17, 8), (1, 9, 504), (2, 17, 520)]]


def topology():
    hsa = ctypes.CDLL("libhsa-runtime64.so.1")
    class agent_t(ctypes.Structure):
        _fields_ = [("handle", ctypes.c_uint64)]
    callback_t = ctypes.CFUNCTYPE(ctypes.c_int, agent_t, ctypes.c_void_p)
    result = []
    hsa.hsa_agent_get_info.argtypes = [agent_t, ctypes.c_int, ctypes.c_void_p]
    hsa.hsa_iterate_agents.argtypes = [callback_t, ctypes.c_void_p]
    @callback_t
    def visit(agent, _):
        kind = ctypes.c_uint32()
        hsa.hsa_agent_get_info(agent, 17, ctypes.byref(kind))
        if kind.value == 1:
            xcd = ctypes.c_uint32()
            status = hsa.hsa_agent_get_info(agent, 0xA111, ctypes.byref(xcd))
            result.append(dict(agent=agent.handle, status=status, xcds=xcd.value))
        return 0
    assert hsa.hsa_init() == 0
    try:
        assert hsa.hsa_iterate_agents(visit, None) == 0
    finally:
        hsa.hsa_shut_down()
    return result


def digest(t):
    return hashlib.sha256(t.contiguous().view(torch.uint8).numpy().tobytes()).hexdigest()


def run(case, args):
    m, n, k = (case[x] for x in ("m", "n", "k"))
    dtype = getattr(torch, args.dtype)
    # Exact dyadic inputs keep hashes stable across installed Torch versions.
    xcpu = (((torch.arange(m*k, dtype=torch.int64)*17+3) % 127)-63).float().reshape(m,k).div(128).to(dtype)
    wcpu = (((torch.arange(n*k, dtype=torch.int64)*29+11) % 131)-65).float().reshape(n,k).div(128).to(dtype)
    bcpu = (((torch.arange(n, dtype=torch.int64)*7+1) % 31)-15).float().div(64).to(dtype) if args.bias else None
    ref = xcpu.float() @ wcpu.float().t()
    if bcpu is not None:
        ref += bcpu.float()
    x, w = xcpu.cuda(), wcpu.cuda()
    b = bcpu.cuda() if bcpu is not None else None
    out_dtype = getattr(torch, args.out_dtype) if args.out_dtype else dtype
    storage = torch.full((m*n+32,), -123.0, dtype=dtype, device="cpu").cuda()
    out = storage[16:-16].view(m,n)
    if args.batched:
        assert m % 2 == 0
        x = x.view(2, m//2, k)
    if args.op == "wvSpltK":
        assert dtype in (torch.float16, torch.bfloat16) and not args.bias and not args.batched and out_dtype == dtype
        def call():
            aiter.wvSpltK(w, x, out, m, torch.cuda.get_device_properties(0).multi_processor_count)
            return out
    elif args.op == "hipb_mm":
        aiter.hipb_create_extension()
        def call():
            return aiter.hipb_mm(x, w.t(), -1, b, out_dtype, bpreshuffle=args.bpreshuffle)
    else:
        from aiter.tuned_gemm import tgemm
        def call():
            return tgemm.mm(x, w, b, out_dtype)
    for _ in range(args.warmup):
        call()
    torch.cuda.synchronize()
    times = []
    print("DUT_BEGIN", case["name"], flush=True)
    for _ in range(args.repeat):
        if args.repeat > 1:
            start, end = torch.cuda.Event(enable_timing=True), torch.cuda.Event(enable_timing=True)
            start.record()
        y = call()
        if args.repeat > 1:
            end.record()
            end.synchronize()
            times.append(start.elapsed_time(end)*1000)
    torch.cuda.synchronize()
    print("DUT_END", case["name"], flush=True)
    got = y.cpu().reshape(m,n)
    assert y.dtype == out_dtype and y.device.type == "cuda", (y.dtype, out_dtype)
    assert tuple(y.shape) == ((2,m//2,n) if args.batched else (m,n)), y.shape
    assert torch.isfinite(got).all()
    err = (got.float()-ref).abs()
    atol, rtol = (0.025, 0.025) if dtype == torch.bfloat16 else (0.003, 0.003)
    ratio = err/(atol+rtol*ref.abs())
    assert ratio.max().item() <= 1, (case, err.max().item(), ratio.max().item())
    assert torch.equal(x.cpu().reshape(m,k), xcpu) and torch.equal(w.cpu(), wcpu)
    if b is not None:
        assert torch.equal(b.cpu(), bcpu)
    if args.op == "wvSpltK":
        saved = storage.cpu()
        assert (saved[:16] == -123).all() and (saved[-16:] == -123).all()
    result = dict(**case, op=args.op, dtype=args.dtype, bias=args.bias, out_dtype=str(out_dtype),
                  input_sha256=digest(xcpu), weight_sha256=digest(wcpu), output_sha256=digest(got),
                  max_abs_error=err.max().item(), max_tolerance_ratio=ratio.max().item(),
                  event_us=times, passed=True)
    if args.op == "mm":
        result["selected_route"] = tgemm.query_sol(m,n,k,args.bias,dtype,out_dtype,False)
    print("PASS", json.dumps(result), flush=True)
    return result


def reject_cases(info):
    from aiter.tuned_gemm import tgemm
    if info["arch"] in ("gfx936", "gfx938", "gfx946"):
        for k in (7, 511, 513):
            assert tgemm.query_skinny(1,9,k,torch.float16) is None
        assert tgemm.query_skinny(1,9,512,torch.bfloat16) == (3,0)
        assert tgemm.query_skinny(1,9,8,torch.float16) == (3,0)
        assert tgemm.query_skinny(1,9,512,torch.float16,True) is None
        assert tgemm.query_skinny(1,1,512,torch.float16) == (3,0)
        assert not tgemm.extensions_created
        info["results"].append(dict(name="selector_capability",passed=True))
    w = torch.empty((9,512), dtype=torch.float16, device="cuda")
    x = torch.empty((2,512), dtype=torch.float16, device="cuda")
    y = torch.empty((2,9), dtype=torch.float16, device="cuda")
    cu = torch.cuda.get_device_properties(0).multi_processor_count
    tests = [
        ("cpu", (torch.empty((9,512),dtype=torch.float16),x,y,2,cu), "CUDA/HIP"),
        ("dtype", (torch.empty_like(w,dtype=torch.bfloat16),x,y,2,cu), "dtypes must match"),
        ("rank", (w.view(-1),x,y,2,cu), "2-D"),
        ("stride", (w.t(),x,y,2,cu), "contiguous"),
        ("input_rows", (w,x,y,1,cu), "N_in"),
        ("too_many_rows", (w,torch.empty((5,512),dtype=x.dtype,device=x.device),y,5,cu), "N_in"),
        ("shape", (w,x,y[:1],2,cu), "shape mismatch"),
        ("cu_count", (w,x,y,2,0), "CuCount"),
        ("k_alignment", (torch.empty((9,7),dtype=x.dtype,device=x.device),torch.empty((2,7),dtype=x.dtype,device=x.device),y,2,cu), "multiple of 8"),
        ("alias", (w,x,w.view(-1)[:18].view(2,9),2,cu), "single memory location"),
    ]
    for name, arguments, message in tests:
        try:
            aiter.wvSpltK(*arguments)
        except (RuntimeError, ValueError) as exc:
            assert message in str(exc), (name,str(exc))
            info["results"].append(dict(name=name,rejected=True,passed=True))
        else:
            raise AssertionError(name+" was accepted")
    multi = any(t["status"] == 0 and t["xcds"] >= 2 for t in info["topology"])
    settings = [("AITER_NORMAL_GEMM_DIE_MODE","bad")]
    settings += ([("AITER_NORMAL_GEMM_DIE_CHUNK",v) for v in ("0","-1","bad")] +
                 [("AITER_NORMAL_GEMM_DIE_MASK","1")]) if multi else [("AITER_NORMAL_GEMM_DIE_MODE","linear")]
    for key,value in settings:
        before = {k:os.environ.get(k) for k in ("AITER_NORMAL_GEMM_DIE_MODE","AITER_NORMAL_GEMM_DIE_CHUNK","AITER_NORMAL_GEMM_DIE_MASK")}
        os.environ.update(AITER_NORMAL_GEMM_DIE_MODE="auto",AITER_NORMAL_GEMM_DIE_CHUNK="1",AITER_NORMAL_GEMM_DIE_MASK="0")
        os.environ[key]=value
        try:
            aiter.wvSpltK(w,x,y,2,cu)
        except (RuntimeError,ValueError) as exc:
            assert "Normal GEMM" in str(exc) or "AITER_NORMAL_GEMM" in str(exc), str(exc)
            info["results"].append(dict(name=f"{key}={value}",rejected=True,passed=True))
        else:
            raise AssertionError(key+"="+value+" was accepted")
        finally:
            for k,v in before.items():
                if v is None: os.environ.pop(k,None)
                else: os.environ[k]=v
    print("CONFIG_PASS",len(info["results"]),flush=True)


def main():
    ap = argparse.ArgumentParser(description=__doc__)
    ap.add_argument("--op", choices=["wvSpltK", "hipb_mm", "mm"], default="wvSpltK")
    ap.add_argument("--case")
    ap.add_argument("--suite", choices=["quick", "full", "boundaries", "config"], default="quick")
    ap.add_argument("--dtype", choices=["float16", "bfloat16"], default="float16")
    ap.add_argument("--out-dtype", choices=["float16", "bfloat16", "float32"])
    ap.add_argument("--bias", action="store_true")
    ap.add_argument("--batched", action="store_true")
    ap.add_argument("--bpreshuffle", action="store_true", help="Capability probe only; plain W is not a shuffled-layout reference")
    ap.add_argument("--require-arch")
    ap.add_argument("--expect-xcds", type=int)
    ap.add_argument("--die-mode", choices=["auto", "off", "linear"], default="auto")
    ap.add_argument("--chunk", type=int, default=1)
    ap.add_argument("--warmup", type=int, default=0)
    ap.add_argument("--repeat", type=int, default=1)
    ap.add_argument("--json")
    ap.add_argument("--list", action="store_true")
    args = ap.parse_args()
    if args.list:
        print(json.dumps(matrix()))
        return
    if args.repeat < 1 or args.warmup < 0:
        ap.error("repeat must be positive and warmup nonnegative")
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
    os.environ.pop("GPU_CHIP", None)
    os.environ["AITER_NORMAL_GEMM_DIE_MODE"] = args.die_mode
    os.environ["AITER_NORMAL_GEMM_DIE_CHUNK"] = str(args.chunk)
    info = dict(torch=torch.__version__, aiter=aiter.__file__, arch=arch, topology=topo,
                device=str(props), arguments=vars(args), results=[])
    info["source_sha256"] = {str(p):hashlib.sha256(p.read_bytes()).hexdigest() for p in
                             (Path(__file__),Path(aiter.__file__).parent/"tuned_gemm.py")}
    print("ENV", json.dumps(info), flush=True)
    cases = matrix() if args.suite == "full" else matrix()[:1]
    if args.suite == "boundaries": cases = boundaries()
    if args.suite == "config": cases = []
    if args.case:
        cases = [next(c for c in matrix()+boundaries()+[dict(name="m8_n9_k512",m=8,n=9,k=512)] if c["name"] == args.case)]
    try:
        if args.suite == "config": reject_cases(info)
        for case in cases:
            info["results"].append(run(case,args))
    finally:
        info["modules"] = {name:dict(path=mod.__file__, sha256=hashlib.sha256(Path(mod.__file__).read_bytes()).hexdigest())
                           for name, mod in list(sys.modules.items())
                           if "module_" in name and getattr(mod,"__file__","") and mod.__file__.endswith(".so") and "aiter" in mod.__file__}
        if args.json:
            Path(args.json).write_text(json.dumps(info,indent=2)+"\n")


if __name__ == "__main__":
    main()
