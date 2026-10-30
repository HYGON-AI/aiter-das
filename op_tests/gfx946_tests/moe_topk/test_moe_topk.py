# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""MoE TopK 单/多 die 的小规模 CPU-reference 验证，不依赖临时文件。

在已配置 HIP/Perf Model 环境并安装 AITER 后，从 AITER 仓库根目录运行：
  export GPU_ARCHS=gfx946
  export GPU_DFLAGS="['StatLog']"
  unset AITER_JIT_DIR PYTHONPATH AITER_REBUILD
  GPU_CHIP=sb python op_tests/gfx946_tests/moe_topk/test_moe_topk.py --expect-xcds 1
  GPU_CHIP=sbx2 python op_tests/gfx946_tests/moe_topk/test_moe_topk.py --expect-xcds 2

当前 PMD 的 GPU_DFLAGS 含 Perf 时（例如 "['Perf']"），可能在需要 scratch
的 moeTopK<256> 上触发 compute_tmpring_size_waves == 0 断言并 core dump。
同一模块、同一输入的对照中，StatLog 和 StatLog+IT0 通过；单独 Perf、
StatLog+Perf、StatLog+IT0+Perf 均复现上述 scratch 断言，退出码134。
上面显式设置 GPU_DFLAGS，避免继承 shell 中的 Perf；单 die quick 已验证24/24。
需要指令 trace 可用 "['StatLog', 'IT0']"；关闭 Perf 是数值验证的绕行方式，
不代表 Perf 采集问题已修复，也不要将这个 scratch 断言与 Barrier 超时混为一谈。

双 die 整批 quick 偶发停在 Barrier packet；已捕获 PMD 的 AsyncEventQueue
生产/消费线程等待同一宿主互斥锁，主线程等待 HSA signal 的状态。停滞点并非
固定 shape，跳过默认 stream 自等待或 HSA_ENABLE_INTERRUPT=0 均不能证明已修复。
这是独立于 Perf scratch 断言的队列推进问题，底层锁状态异常原因仍需 PMD 侧定位。
PMD 每个用例仅调用一次；定位问题可按 --ops 和 --dtypes 拆进程验证quick/full。
拆分也不能消除停滞：本次12个quick进程中11个完成，最后一个在首例通过后超时
（合计23例通过、1例未完成）。目前没有验证可靠的Barrier绕行方式，示例为验证/复现命令：
  for op in topk_softmax fused_topk grouped_topk biased_grouped_topk; do
    for dtype in fp32 fp16 bf16; do
      GPU_CHIP=sbx2 python op_tests/gfx946_tests/moe_topk/test_moe_topk.py --ops "$op" --dtypes "$dtype" --expect-xcds 2
    done
  done

完整矩阵、路由和配置检查示例：
  GPU_CHIP=sbx2 python op_tests/gfx946_tests/moe_topk/test_moe_topk.py --suite full --ops biased_grouped_topk --dtypes bf16 --expect-xcds 2
  GPU_CHIP=sbx2 python op_tests/gfx946_tests/moe_topk/test_moe_topk.py --suite route --ops topk_softmax --dtypes fp32 --die-mode linear --chunk 1 --expect-xcds 2 --non-default-stream
  for op in topk_softmax fused_topk grouped_topk biased_grouped_topk; do
    GPU_CHIP=sbx2 python op_tests/gfx946_tests/moe_topk/test_moe_topk.py --suite config --ops "$op" --expect-xcds 2
  done

route 可换4个公共入口、--chunk 2，或 --route-path fallback/optimized/shared。
数值 PASS 不证明双 XCD 都执行了 TG，还需检查同一 dispatch 的 completedWGs。
off 表示普通启动 API，不表示硬件只使用一个 die。GPU_CHIP 仅选择 PMD 模型，
测试初始化后删除它；真实硬件不需要此变量。当前 PMD 集中运行 config 也曾长时间
停在 Barrier packet，可用上面的按接口拆进程命令定位。单次通过不代表 PMD 队列问题已修复。
Graph 和性能不包含在此测试中。
"""
import argparse
import ctypes
import ctypes.util
import hashlib
import importlib
import json
import os
from pathlib import Path
import time
from unittest.mock import patch

import torch
import aiter
from aiter.fused_moe import fused_topk

OPS = ('topk_softmax', 'fused_topk', 'grouped_topk', 'biased_grouped_topk')
DTYPES = {'fp32': torch.float32, 'fp16': torch.float16, 'bf16': torch.bfloat16}


def topology():
    class Agent(ctypes.Structure):
        _fields_ = [('handle', ctypes.c_uint64)]
    hsa = ctypes.CDLL(ctypes.util.find_library('hsa-runtime64') or 'libhsa-runtime64.so.1')
    callback_type = ctypes.CFUNCTYPE(ctypes.c_uint32, Agent, ctypes.c_void_p)
    hsa.hsa_agent_get_info.argtypes = [Agent, ctypes.c_int, ctypes.c_void_p]
    hsa.hsa_iterate_agents.argtypes = [callback_type, ctypes.c_void_p]
    found = []
    @callback_type
    def visit(agent, unused):
        device = ctypes.c_uint32()
        status = hsa.hsa_agent_get_info(agent, 17, ctypes.byref(device))
        if status or device.value != 1:
            return status
        name, xcds = ctypes.create_string_buffer(64), ctypes.c_uint32()
        assert hsa.hsa_agent_get_info(agent, 0, name) == 0
        status = hsa.hsa_agent_get_info(agent, 0xA111, ctypes.byref(xcds))
        found.append(dict(name=name.value.decode(), xcds=xcds.value, status=status))
        return 0
    assert hsa.hsa_init() == 0
    try:
        assert hsa.hsa_iterate_agents(visit, None) == 0
    finally:
        assert hsa.hsa_shut_down() == 0
    return found


def case(op, m=5, e=64, k=4, groups=4, group_k=2, renorm=True,
         softmax=True, scale=1., shared=0, force_gate=False, padded=False):
    return dict(op=op, m=m, e=e, k=k, groups=groups, group_k=group_k,
                renorm=renorm, softmax=softmax, scale=scale, shared=shared,
                force_gate=force_gate, padded=padded)


def run_case(c, dtype_name, non_default_stream=False):
    op, m, e, k = (c[x] for x in ('op', 'm', 'e', 'k'))
    biased = op == 'biased_grouped_topk'
    grouped = op in ('grouped_topk', 'biased_grouped_topk')
    gate = biased and (c['shared'] > 0 or c['force_gate'])
    softmax = c['softmax'] and not biased
    dtype = DTYPES[dtype_name]
    # 每行随机排列不同的间隔值，避免 dtype 舍入造成选择边界歧义。
    generator = torch.Generator().manual_seed(946 + e + m)
    base = torch.linspace(-2., 2., e)
    xcpu = torch.stack([base[torch.randperm(e, generator=generator)] for _ in range(m)]).to(dtype)
    bcpu = (torch.arange(e).remainder(11).float() * .003 - .015).to(dtype)
    scores = torch.softmax(xcpu.float(), -1) if softmax else torch.sigmoid(xcpu.float())
    choice = scores + bcpu.float() if biased else scores.clone()
    if grouped:
        grouped_choice = choice.reshape(m, c['groups'], -1)
        group_score = (grouped_choice.topk(2, -1).values.sum(-1) if biased
                       else grouped_choice.max(-1).values)
        groups = group_score.topk(c['group_k'], -1).indices
        mask = torch.zeros_like(group_score, dtype=torch.bool).scatter_(1, groups, True)
        choice = choice.masked_fill(~mask.repeat_interleave(e // c['groups'], -1), -float('inf'))
    routed = k - c['shared']
    expected_ids = choice.topk(routed, -1).indices
    expected = scores.gather(1, expected_ids)
    if c['renorm'] or gate:
        expected = expected / expected.sum(-1, keepdim=True)
    if grouped and not gate:
        expected = expected * c['scale']
    if c['shared']:
        expected_ids = torch.cat((expected_ids, torch.arange(e, e+c['shared']).expand(m,-1)), -1)
        expected = torch.cat((expected, torch.full((m,c['shared']), 1./c['scale'])), -1)

    x, bias = xcpu.cuda(), bcpu.cuda()
    stride = k + (3 if c['padded'] else 0)
    weights_base = torch.full((m+2, stride), -77., dtype=torch.float32).cuda()
    ids_base = torch.full((m+2, stride), -77, dtype=torch.int32).cuda()
    weights, ids = weights_base[1:-1,:k], ids_base[1:-1,:k]
    token_base = torch.full((m*k+2,), -77, dtype=torch.int32).cuda()
    token_indices = token_base[1:-1].reshape(m,k)
    hidden = torch.empty((m,1), dtype=dtype, device='cuda')
    stream = torch.cuda.Stream() if non_default_stream else torch.cuda.current_stream()
    stream.wait_stream(torch.cuda.current_stream())
    with torch.cuda.stream(stream):
        if op == 'topk_softmax':
            aiter.topk_softmax(weights, ids, token_indices, x, c['renorm'])
        elif op == 'fused_topk':
            w, i = fused_topk(hidden, x, k, c['renorm'], ids, weights, c['softmax'])
            assert w.data_ptr() == weights.data_ptr() and i.data_ptr() == ids.data_ptr()
        elif op == 'grouped_topk':
            aiter.grouped_topk(x, weights, ids, c['groups'], c['group_k'], c['renorm'], c['softmax'], c['scale'])
        else:
            args = (x, bias, weights, ids, c['groups'], c['group_k'], c['shared'], c['renorm'], c['scale'])
            if c['force_gate']:
                # 仅强制公共 wrapper 的大 token 分支，避免模拟上万行；不替换 kernel。
                with patch.object(importlib.import_module('aiter.ops.topk'), 'get_cu_num', return_value=0):
                    aiter.biased_grouped_topk(*args)
            else:
                aiter.biased_grouped_topk(*args)
    stream.synchronize()
    wb, ib = weights_base.cpu(), ids_base.cpu()
    got_w, got_i = wb[1:-1,:k], ib[1:-1,:k].long()
    expected_order = expected_ids.argsort(-1)
    got_order = got_i.argsort(-1)
    assert torch.equal(got_i.gather(1,got_order), expected_ids.gather(1,expected_order)), (got_i,expected_ids)
    # HIP exp/rcp 与 CPU 的 FP32 求值可能有几个 ULP 差异，选择索引仍要求完全一致。
    torch.testing.assert_close(got_w.gather(1,got_order), expected.gather(1,expected_order), atol=2e-6, rtol=2e-5)
    assert (wb[[0,-1]] == -77).all() and (ib[[0,-1]] == -77).all()
    assert (wb[1:-1,k:] == -77).all() and (ib[1:-1,k:] == -77).all()
    assert torch.equal(x.cpu(),xcpu) and torch.equal(bias.cpu(),bcpu)
    if op == 'topk_softmax':
        want_tokens = torch.arange(k)[None,:]*m + torch.arange(m)[:,None]
        assert torch.equal(token_indices.cpu().long(),want_tokens)
    assert (token_base.cpu()[[0,-1]] == -77).all()
    return dict(**c,dtype=dtype_name,max_error=float((got_w.gather(1,got_order)-expected.gather(1,expected_order)).abs().max()))


def matrix(op, suite, route_path):
    if suite == 'route':
        if route_path == 'sigmoid' and op in ('fused_topk','grouped_topk'):
            return [case(op,softmax=False)]
        if op in ('topk_softmax','fused_topk'):
            # FP32 E512 fused: 2 rows/TG，9行产生5个TG；fallback 每行1TG。
            return [case(op,m=5 if route_path=='fallback' else 9,e=192 if route_path=='fallback' else 512)]
        if op == 'biased_grouped_topk' and route_path == 'shared':
            return [case(op,m=33,e=256,k=9,groups=8,group_k=4,shared=1,scale=2.)]
        return [case(op,e=256 if route_path=='optimized' else 64,k=8 if route_path=='optimized' else 4,
                     groups=8 if route_path=='optimized' else 4,group_k=4 if route_path=='optimized' else 2)]
    if op in ('topk_softmax','fused_topk'):
        result = [case(op,e=64),case(op,e=192,renorm=False)]
        if suite == 'full':
            result += [case(op,m=1,e=e,k=min(e,3),renorm=False) for e in (1,2,4,8,16,32,128,256,512,1024)]
            result += [case(op,e=256,padded=True)]
            if op == 'fused_topk':
                result += [case(op,softmax=False,renorm=r) for r in (True,False)]
        return result
    result = [case(op),case(op,renorm=False,softmax=False,scale=1.7)]
    if suite == 'full':
        result += [case(op,e=64,groups=g,group_k=max(1,g//2),softmax=s,renorm=r,scale=1.7,padded=True)
                   for g,s,r in ((1,False,True),(2,True,False),(8,False,True))]
        result += [case(op,e=66,groups=2,group_k=1),case(op,e=63,groups=1,group_k=1)]
        if op == 'biased_grouped_topk':
            result += [case(op,e=256,k=8,groups=8,group_k=4,renorm=r,scale=1.7) for r in (True,False)]
            result += [case(op,e=e,groups=8,group_k=4,k=6,shared=shared,scale=2.,force_gate=shared==0)
                       for e,shared in ((256,1),(192,2),(64,1),(128,0))]
    return result


def main():
    p=argparse.ArgumentParser(description=__doc__)
    p.add_argument('--suite',choices=('quick','full','route','config'),default='quick')
    p.add_argument('--ops',nargs='+',choices=OPS,default=list(OPS))
    p.add_argument('--dtypes',nargs='+',choices=DTYPES,default=['fp32','fp16','bf16'])
    p.add_argument('--die-mode',choices=('auto','off','linear'),default='auto')
    p.add_argument('--chunk',type=int,default=1)
    p.add_argument('--route-path',choices=('ordinary','fallback','optimized','shared','sigmoid'),default='ordinary')
    p.add_argument('--expect-xcds',type=int)
    p.add_argument('--require-arch',default='gfx946')
    p.add_argument('--non-default-stream',action='store_true')
    p.add_argument('--json')
    args=p.parse_args()
    torch.set_num_threads(1)
    torch.cuda.init()
    arch=torch.cuda.get_device_properties(0).gcnArchName.split(':')[0]
    assert arch == args.require_arch,(arch,args.require_arch)
    topo=topology() if args.expect_xcds is not None else []
    if args.expect_xcds is not None:
        assert topo and all(x['status']==0 and x['xcds']==args.expect_xcds for x in topo),topo
    os.environ.pop('GPU_CHIP',None)
    os.environ['AITER_MOE_TOPK_DIE_MODE']=args.die_mode
    os.environ['AITER_MOE_TOPK_DIE_CHUNK']=str(args.chunk)
    os.environ['AITER_MOE_TOPK_DIE_MASK']='0'
    os.environ['AITER_MOE_TOPK_LOG_LAUNCH']='1'
    print('ENV',dict(arch=arch,topology=topo,aiter=aiter.__file__),flush=True)
    records=[]
    for op in args.ops:
        if args.suite == 'config':
            configs=[('AITER_MOE_TOPK_DIE_MODE','invalid')]
            if args.expect_xcds == 2:
                configs += [('AITER_MOE_TOPK_DIE_CHUNK',v) for v in ('0','-1','abc','4294967296')]
                configs += [('AITER_MOE_TOPK_DIE_MASK','1')]
            else:
                configs += [('AITER_MOE_TOPK_DIE_MODE','linear')]
            for key,value in configs:
                saved=dict(os.environ)
                os.environ['AITER_MOE_TOPK_DIE_MODE']='linear'
                os.environ[key]=value
                try:
                    try: run_case(case(op), 'fp32')
                    except (RuntimeError,ValueError) as exc:
                        assert 'MoE TopK' in str(exc) or 'AITER_MOE_TOPK' in str(exc),str(exc)
                        records.append(dict(op=op,config={key:value},passed=True))
                    else: raise AssertionError('invalid configuration was accepted')
                finally:
                    os.environ.clear();os.environ.update(saved)
            # 普通启动不解析无关的 chunk/mask；auto 单 TG 回退同理。
            for mode in ('off','auto'):
                saved=dict(os.environ)
                os.environ.update(AITER_MOE_TOPK_DIE_MODE=mode,AITER_MOE_TOPK_DIE_CHUNK='0',AITER_MOE_TOPK_DIE_MASK='1')
                try:
                    r=run_case(case(op,m=1),'fp32')
                    records.append(dict(op=op,ignored_config=mode,passed=True))
                finally:
                    os.environ.clear();os.environ.update(saved)
        else:
            for dtype in args.dtypes:
                for c in matrix(op,args.suite,args.route_path):
                    if args.suite == 'route' and op == 'topk_softmax' and c['e'] == 512 and dtype != 'fp32':
                        c['m'] = 17  # FP16/BF16 的向量宽度较大，每 TG 处理4行。
                    start=time.monotonic()
                    try:
                        r=run_case(c,dtype,args.non_default_stream)
                        r.update(passed=True,seconds=time.monotonic()-start)
                    except Exception as exc:
                        r=dict(**c,dtype=dtype,passed=False,error=str(exc))
                    records.append(r)
                    print('CASE',json.dumps(r),flush=True)
    modules={}
    import sys
    for name,module in list(sys.modules.items()):
        path=getattr(module,'__file__',None)
        if path and 'module_cpp_api' in name and path.endswith('.so'):
            modules[path]=hashlib.sha256(Path(path).read_bytes()).hexdigest()
    result=dict(arch=arch,topology=topo,modules=modules,passed=sum(r['passed'] for r in records),
                failed=sum(not r['passed'] for r in records),cases=records)
    if args.json: Path(args.json).write_text(json.dumps(result,indent=2),encoding='utf-8')
    print('RESULT',json.dumps({k:v for k,v in result.items() if k!='cases'}),flush=True)
    assert not result['failed'],f"{result['failed']} cases failed"


if __name__ == '__main__':
    main()
