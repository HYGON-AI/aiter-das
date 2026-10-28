# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Compare public W8A8 APIs with torch.mm on pre-dequantized BF16 inputs.

Hardware only. No imports or data inputs from temporary directories. JSON is
an optional output. JIT, input generation, dequantization and correctness are
outside timing. AITER scales and MX scale decoding remain inside its timing.
"""
import argparse
import hashlib
import json
import math
import os
from pathlib import Path
import statistics
import time

import torch
import aiter


DEFAULT_SHAPES = [(1,4096,4096),(16,4096,4096),(128,4096,4096),(1024,4096,4096),
                  (16,14336,4096),(128,14336,4096),(16,4096,14336),(128,4096,14336)]


def make_inputs(op, shape):
    m,n,k = shape
    quant = torch.int8 if op=='row_int8' else torch.float8_e4m3fn
    a = torch.randint(-16,17,(m,k),device='cuda').float()
    b = torch.randint(-16,17,(n,k),device='cuda').float()
    if quant != torch.int8:
        a.mul_(.25)
        b.mul_(.25)
    a,b = a.to(quant),b.to(quant)
    if op.startswith('row_'):
        sa = torch.exp2((torch.arange(m,device='cuda')%3-3).float()).view(m,1)
        sb = torch.exp2((torch.arange(n,device='cuda')%3-3).float()).view(1,n)
        da,db = (a.float()*sa).bfloat16(),(b.float()*sb.T).bfloat16()
        fn = lambda: aiter.gemm_a8w8_CK(a,b,sa,sb,dtype=torch.bfloat16,splitK=0)
    else:
        g = 32 if op=='mx32' else 128
        assert n%g==0 and k%g==0
        ea = (torch.arange(m*(k//g),device='cuda')%3-3).reshape(m,k//g)
        eb = (torch.arange((n//g)*(k//g),device='cuda')%3-3).reshape(n//g,k//g)
        saf,sbf = torch.exp2(ea.float()),torch.exp2(eb.float())
        da = (a.float().reshape(m,k//g,g)*saf[:,:,None]).reshape(m,k).bfloat16()
        db = (b.float().reshape(n//g,g,k//g,g)*sbf[:,None,:,None]).reshape(n,k).bfloat16()
        sa,sb = ((ea+127).byte(),(eb+127).byte()) if op=='mx32' else (saf,sbf)
        fn = lambda: aiter.gemm_a8w8_blockscale(a,b,sa,sb,dtype=torch.bfloat16)
    # Scale powers of two keep dequantization exact in BF16 for these inputs.
    baseline = lambda: torch.mm(da,db.T)
    return a,da,db,fn,baseline


def check(out, reference):
    torch.testing.assert_close(out,reference,rtol=.02,atol=.02)
    return (out.float()-reference.float()).abs().max().item()


def capture(fn, inner):
    stream = torch.cuda.Stream()
    stream.wait_stream(torch.cuda.current_stream())
    with torch.cuda.stream(stream):
        for _ in range(5): fn()
    stream.synchronize()
    graph = torch.cuda.CUDAGraph()
    with torch.cuda.graph(graph,stream=stream):
        for _ in range(inner): output=fn()
    torch.cuda.current_stream().wait_stream(stream)
    graph.replay()
    torch.cuda.synchronize()
    return graph,output


def graph_sample(graph, inner, repeats):
    start,end = torch.cuda.Event(enable_timing=True),torch.cuda.Event(enable_timing=True)
    start.record()
    for _ in range(repeats): graph.replay()
    end.record()
    end.synchronize()
    return start.elapsed_time(end)*1000/(repeats*inner)


def eager_sample(fn, repeats):
    torch.cuda.synchronize()
    start=time.perf_counter()
    for _ in range(repeats): fn()
    torch.cuda.synchronize()
    return (time.perf_counter()-start)*1e6/repeats


def stats(samples):
    return dict(median_us=statistics.median(samples),min_us=min(samples),
                max_us=max(samples),samples_us=samples)


def benchmark_pair(functions,graphs,inner,rounds,target_ms):
    results={mode:{name:[] for name in functions} for mode in ('eager_wall','graph_gpu')}
    counts={mode:{} for mode in results}
    for name,fn in functions.items():
        eg = eager_sample(fn,3)
        gr = graph_sample(graphs[name],inner,2)
        counts['eager_wall'][name]=max(5,min(1000,math.ceil(target_ms*1000/eg)))
        counts['graph_gpu'][name]=max(2,min(256,math.ceil(target_ms*1000/(gr*inner))))
    for mode in results:
        for r in range(rounds):
            # Alternate A/B order to reduce order/clock bias on the same GPU.
            order=list(functions) if r%2==0 else list(reversed(functions))
            for name in order:
                count=counts[mode][name]
                value=(eager_sample(functions[name],count) if mode=='eager_wall'
                       else graph_sample(graphs[name],inner,count))
                results[mode][name].append(value)
    return {mode:dict(measurements={name:stats(samples) for name,samples in values.items()},
                      iterations=counts[mode],
                      speedup=statistics.median(values['torch_mm'])/statistics.median(values['aiter']))
            for mode,values in results.items()}


@torch.inference_mode()
def main():
    parser=argparse.ArgumentParser(description=__doc__)
    parser.add_argument('--shape',action='append',help='M,N,K; repeatable')
    parser.add_argument('--ops',nargs='+',choices=('row_int8','row_fp8','block128','mx32'),
                        default=['row_int8','row_fp8','block128','mx32'])
    parser.add_argument('--rounds',type=int,default=5)
    parser.add_argument('--graph-inner',type=int,default=16)
    parser.add_argument('--target-ms',type=float,default=20)
    parser.add_argument('--require-arch',default='gfx938')
    parser.add_argument('--json',type=Path)
    args=parser.parse_args()
    assert args.rounds>0 and args.graph_inner>0 and args.target_ms>0
    assert not os.environ.get('GPU_CHIP'), 'Hardware benchmark: remove PMD GPU_CHIP'
    prop=torch.cuda.get_device_properties(torch.cuda.current_device())
    assert prop.gcnArchName.split(':')[0]==args.require_arch,prop
    torch.manual_seed(938)
    torch.set_num_threads(1)
    torch.backends.cuda.matmul.allow_tf32=False
    torch.backends.cuda.matmul.allow_bf16_reduced_precision_reduction=False
    report=dict(complete=False,torch=torch.__version__,hip=torch.version.hip,
                aiter=aiter.__file__,device=str(prop),visible=os.environ.get('HIP_VISIBLE_DEVICES'),
                args={k:str(v) if isinstance(v,Path) else v for k,v in vars(args).items()},
                script_sha256=hashlib.sha256(Path(__file__).read_bytes()).hexdigest(),cases=[])
    def save():
        if args.json: args.json.write_text(json.dumps(report,indent=2)+'\n')
    print('IDENTITY',json.dumps(report),flush=True)
    save()
    shapes=[tuple(map(int,s.split(','))) for s in args.shape] if args.shape else DEFAULT_SHAPES
    for shape in shapes:
        for op in args.ops:
            try:
                a,da,db,fn,baseline=make_inputs(op,shape)
                reference=torch.mm(da.float(),db.float().T).bfloat16()
                error=check(fn(),reference)
                baseline_error=check(baseline(),reference)
                ga,oa=capture(fn,args.graph_inner)
                gb,ob=capture(baseline,args.graph_inner)
                check(oa,reference)
                check(ob,reference)
                # Replay must consume changed inputs, not the capture-time values.
                saved_a,saved_da=a.clone(),da.clone()
                a.zero_();da.zero_()
                ga.replay();gb.replay();torch.cuda.synchronize()
                assert torch.count_nonzero(oa)==0 and torch.count_nonzero(ob)==0
                a.copy_(saved_a);da.copy_(saved_da)
                ga.replay();gb.replay();torch.cuda.synchronize()
                check(oa,reference);check(ob,reference)
                result=benchmark_pair(dict(aiter=fn,torch_mm=baseline),dict(aiter=ga,torch_mm=gb),
                                      args.graph_inner,args.rounds,args.target_ms)
                case=dict(op=op,shape=shape,status='PASS',output='bf16',max_abs=error,
                          torch_mm_max_abs=baseline_error,graph_changed_input=True,**result)
                report['cases'].append(case)
                print('CASE',json.dumps(case),flush=True)
                save()
                del ga,gb,oa,ob,reference,saved_a,saved_da,fn,baseline,a,da,db
            except Exception as error:
                report['cases'].append(dict(op=op,shape=shape,status='FAIL',error=str(error)))
                save()
                raise
    from aiter.jit.core import get_module
    report['modules']=[]
    modules=set('module_gemm_a8w8' if op.startswith('row_') else 'module_gemm_a8w8_blockscale'
                for op in args.ops)
    for name in sorted(modules):
        path=Path(get_module(name).__file__)
        report['modules'].append(dict(name=name,path=str(path),sha256=hashlib.sha256(path.read_bytes()).hexdigest()))
    report['complete']=True
    save()
    print('RESULT PASS',len(report['cases']),'cases',flush=True)


if __name__=='__main__':
    main()
