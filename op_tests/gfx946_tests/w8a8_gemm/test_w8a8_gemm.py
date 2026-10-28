# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Self-contained W8A8 tests: AITER, Torch, HIP and stdlib only.

Configure HIP/PMD before starting Python. --rebuild rebuilds normal AITER JIT
modules; --json is an optional output, never an input dependency. Each case
calls the public operator once, without warmup or timing repetitions.
"""
import argparse
import ctypes
import ctypes.util
import json
import os
from pathlib import Path


def query_xcds():
    class Agent(ctypes.Structure):
        _fields_ = [('handle', ctypes.c_uint64)]
    hsa = ctypes.CDLL(ctypes.util.find_library('hsa-runtime64') or 'libhsa-runtime64.so.1')
    callback = ctypes.CFUNCTYPE(ctypes.c_uint32, Agent, ctypes.c_void_p)
    hsa.hsa_agent_get_info.argtypes = [Agent, ctypes.c_int, ctypes.c_void_p]
    hsa.hsa_iterate_agents.argtypes = [callback, ctypes.c_void_p]
    counts = []
    @callback
    def visit(agent, unused):
        device, count = ctypes.c_uint32(), ctypes.c_uint32()
        status = hsa.hsa_agent_get_info(agent, 17, ctypes.byref(device))
        if status or device.value != 1:
            return status
        status = hsa.hsa_agent_get_info(agent, 0xA111, ctypes.byref(count))
        if not status:
            counts.append(count.value)
        return status
    assert hsa.hsa_init() == 0
    try:
        assert hsa.hsa_iterate_agents(visit, None) == 0
    finally:
        assert hsa.hsa_shut_down() == 0
    assert counts
    return counts


def cases_for(op, suite):
    small = (3,128,256) if op == 'blockscale' else (3,32,128)
    # Eight GEMM workgroups with the selected HCU instances.
    route = (17,256,128) if op == 'rowwise' else (17,128,128)
    if suite == 'quick':
        return [dict(shape=small)]
    if suite == 'full':
        shapes = {'rowwise': [(1,16,32),(3,20,128),(17,32,256),(5,16,640)],
                  'blockscale': [(1,128,128),(3,136,256),(17,256,384),(5,128,640)],
                  'mx': [(1,16,32),(3,32,128),(17,48,256),(5,32,640)]}[op]
        return [dict(shape=s,bias=(op=='rowwise' and i%2==1),scale_output=(op=='rowwise' and i>=2),
                     stream=(i==3),out_form=(i%2==0),zeros=(i==0)) for i,s in enumerate(shapes)]
    if suite == 'optimized':
        # Keep K small for CPU-based Perf Model execution while exercising the
        # small/medium/large-M dispatch boundaries and padded M/N/K together.
        shapes = [(16,128,128),(64,128,128),(512,128,32),(65,136,160)]
        return [dict(shape=s,bias=(op=='rowwise'),scale_output=(op=='rowwise' and i%2==1),
                     stream=(i==3),out_form=(i%2==0)) for i,s in enumerate(shapes)]
    if suite == 'route':
        return [dict(shape=route,mode='linear',chunk=c) for c in (1,2)]
    return [dict(shape=(1,16,128),mode='auto'),
            dict(shape=route,mode='linear',chunk=2),dict(shape=small,mode='off')]


def run_case(torch, aiter, op, qdtype, dtype, case):
    m,n,k = case['shape']
    a = (torch.randint(-16,17,(m,k)).float()*(.25 if qdtype!=torch.int8 else 1)).to(qdtype)
    b = (torch.randint(-16,17,(n,k)).float()*(.25 if qdtype!=torch.int8 else 1)).to(qdtype)
    if case.get('zeros'):
        a = torch.zeros((m,k)).to(qdtype)
    bias = torch.linspace(-.5,.5,n).to(dtype) if case.get('bias') else None
    if op == 'rowwise':
        st = dtype if case.get('scale_output') else torch.float32
        sa,sb = torch.linspace(.125,.375,m).reshape(m,1).to(st),torch.linspace(.125,.375,n).reshape(1,n).to(st)
        ref = (a.float()@b.float().T)*sb.float()*sa.float()
        if bias is not None:
            ref += bias.float()
    else:
        g = 32 if op=='mx' else 128
        sk,sn = (k+g-1)//g,(n+g-1)//g
        if op=='mx':
            sa,sb = (torch.arange(m*sk).reshape(m,sk)%4+124).byte(),(torch.arange(sn*sk).reshape(sn,sk)%5+124).byte()
            saf,sbf = torch.exp2(sa.float()-127),torch.exp2(sb.float()-127)
            if hasattr(torch,'float8_e8m0fnu') and case.get('out_form'):
                sa,sb = sa.view(torch.float8_e8m0fnu),sb.view(torch.float8_e8m0fnu)
        else:
            sa,sb = torch.linspace(.125,.375,m*sk).reshape(m,sk),torch.linspace(.2,.6,sn*sk).reshape(sn,sk)
            saf,sbf = sa,sb
        aa = a.float()*saf.repeat_interleave(g,1)[:,:k]
        bb = b.float()*sbf.repeat_interleave(g,0).repeat_interleave(g,1)[:n,:k]
        ref = aa@bb.T
    ref = ref.to(dtype)
    stream = torch.cuda.Stream() if case.get('stream') else torch.cuda.current_stream()
    with torch.cuda.stream(stream):
        ga,gb,gsa,gsb = (t.cuda() for t in (a,b,sa,sb))
        if op=='rowwise':
            out = aiter.gemm_a8w8_CK(ga,gb,gsa,gsb,None if bias is None else bias.cuda(),dtype,splitK=0)
        else:
            backing = torch.full((m*n+16,),-23,dtype=dtype).cuda()
            target = backing[8:-8].view(m,n)
            if case.get('out_form',True):
                out = aiter.gemm_a8w8_blockscale(ga,gb,gsa,gsb,target)
                assert out.data_ptr()==target.data_ptr()
            else:
                out = aiter.gemm_a8w8_blockscale(ga,gb,gsa,gsb,dtype=dtype)
        stream.synchronize()
        got = out.cpu()
        if op!='rowwise':
            host = backing.cpu()
            assert (host[:8]==-23).all() and (host[-8:]==-23).all(), 'output guard overwritten'
    torch.testing.assert_close(got,ref,rtol=.02 if dtype==torch.bfloat16 else .002,atol=.02)
    return dict(max_abs=(got.float()-ref.float()).abs().max().item(),input=str(qdtype),output=str(dtype),**case)


def main():
    p = argparse.ArgumentParser(description=__doc__)
    p.add_argument('--suite',choices=('quick','full','optimized','multi','route','invalid','single-reject','contracts'),default='quick')
    p.add_argument('--ops',nargs='+',choices=('rowwise','blockscale','mx'),default=['rowwise','blockscale','mx'])
    p.add_argument('--dtypes',nargs='+',choices=('fp16','bf16'),default=['fp16','bf16'])
    p.add_argument('--qdtypes',nargs='+',choices=('int8','fp8'),default=['int8','fp8'])
    p.add_argument('--rebuild',action='store_true')
    p.add_argument('--require-arch',default='gfx946')
    p.add_argument('--expect-xcds',type=int)
    p.add_argument('--json',type=Path)
    args = p.parse_args()
    if args.rebuild:
        os.environ['AITER_REBUILD']='1'
    import torch
    import aiter
    props = torch.cuda.get_device_properties(torch.cuda.current_device())
    arch = props.gcnArchName.split(':')[0]
    assert arch==args.require_arch,(arch,args.require_arch)
    os.environ.pop('GPU_CHIP',None)
    xcds = query_xcds() if args.expect_xcds else []
    if args.expect_xcds:
        assert all(x==args.expect_xcds for x in xcds),(xcds,args.expect_xcds)
    os.environ['CK_W8A8_LOG_LAUNCH']='1'
    torch.manual_seed(946)
    torch.set_num_threads(1)
    report = dict(arch=arch,xcds=xcds,torch=torch.__version__,hip=torch.version.hip,
                  aiter=aiter.__file__,suite=args.suite,complete=False,cases=[])
    print('ENV',json.dumps(report),flush=True)
    def record(case):
        report['cases'].append(case)
        print(case['status'],json.dumps(case),flush=True)
        if args.json:
            args.json.write_text(json.dumps(report,indent=2)+'\n')
    for op in args.ops:
        if args.suite == 'contracts':
            m,n,k = 3,32,128
            group = 32 if op=='mx' else 128
            a,b = torch.zeros((m,k)).to(torch.float8_e4m3fn).cuda(),torch.zeros((n,k)).to(torch.float8_e4m3fn).cuda()
            sa = torch.ones((m,1) if op=='rowwise' else (m,k//group)).cuda()
            sb = torch.ones((1,n) if op=='rowwise' else (1,k//group)).cuda()
            if op=='mx':
                sa,sb = torch.full((m,k//group),127,dtype=torch.uint8).cuda(),torch.full((1,k//group),127,dtype=torch.uint8).cuda()
            fn = aiter.gemm_a8w8_CK if op=='rowwise' else aiter.gemm_a8w8_blockscale
            for name, tensors, kwargs in [
                ('bad_k',(a,b[:,:64],sa,sb),{}),
                ('bad_scales',(a,b,sa[:1],sb),{}),
                ('bad_dtype',(a,b,sa,sb),dict(dtype=torch.float32)),
                ('noncontiguous',(a[:,::2],b[:,::2],sa,sb),{}),
            ]:
                try:
                    fn(*tensors,**kwargs)
                except (ValueError,RuntimeError) as error:
                    record(dict(op=op,check=name,status='PASS',rejected=str(error).splitlines()[0]))
                else:
                    raise AssertionError(f'{name} accepted')
            empty=fn(a[:0],b,sa[:0],sb,dtype=torch.bfloat16)
            assert empty.shape==(0,n) and empty.dtype==torch.bfloat16
            record(dict(op=op,check='empty_m',status='PASS'))
            if op=='rowwise':
                try:
                    fn(a,b,sa,sb,splitK=1)
                except RuntimeError as error:
                    assert 'splitK=0' in str(error)
                    record(dict(op=op,check='splitK_reject',status='PASS'))
                else:
                    raise AssertionError('splitK=1 accepted')
            continue
        if args.suite in ('invalid','single-reject'):
            configs = [('linear','1','0')] if args.suite=='single-reject' else [
                ('bad','1','0'),('linear','0','0'),('linear','-1','0'),('linear','1','1'),('linear','4294967296','0')]
            for mode,chunk,mask in configs:
                os.environ.update(CK_W8A8_DIE_MODE=mode,CK_W8A8_DIE_CHUNK=chunk,CK_W8A8_DIE_MASK=mask)
                try:
                    run_case(torch,aiter,op,torch.float8_e4m3fn,torch.float16,cases_for(op,'quick')[0])
                except (RuntimeError,ValueError) as error:
                    assert 'W8A8' in str(error),str(error)
                    record(dict(op=op,mode=mode,chunk=chunk,mask=mask,status='PASS',rejected=str(error).splitlines()[0]))
                else:
                    raise AssertionError('invalid launch configuration accepted')
            continue
        for quant in (args.qdtypes if op=='rowwise' else ['fp8']):
            for name in args.dtypes:
                for case in cases_for(op,args.suite):
                    os.environ.update(CK_W8A8_DIE_MODE=case.get('mode','auto'),
                                      CK_W8A8_DIE_CHUNK=str(case.get('chunk',1)),CK_W8A8_DIE_MASK='0')
                    result = run_case(torch,aiter,op,torch.int8 if quant=='int8' else torch.float8_e4m3fn,
                                      torch.float16 if name=='fp16' else torch.bfloat16,case)
                    record(dict(op=op,status='PASS',**result))
    report['complete']=True
    if args.json:
        args.json.write_text(json.dumps(report,indent=2)+'\n')
    print(f"RESULT PASS {len(report['cases'])} cases",flush=True)


if __name__=='__main__':
    main()
