"""Direct AR+MHC one-stage/automatic/split contracts and Graph replay."""
from datetime import timedelta
import os
import torch
import torch.distributed as dist
from aiter.dist.device_communicators.custom_all_reduce import CustomAllreduce
from aiter.ops import custom_all_reduce as ops


def main():
    rank,local,world=[int(os.environ[k]) for k in ('RANK','LOCAL_RANK','WORLD_SIZE')]
    torch.cuda.set_device(local);device=torch.device('cuda',local)
    dist.init_process_group('gloo',timeout=timedelta(seconds=180))
    ca=CustomAllreduce(dist.group.WORLD,device,max_size=32*1024*1024,enable_register_for_capturing=False)
    assert not ca.disabled
    count=0
    try:
        for dtype in (torch.float16,torch.bfloat16):
            tol=.008 if dtype==torch.float16 else .04
            for tokens,width in ((4,256),(4,512),(4,2048),(129,4096),(128,7168),(8192,512)):
                x=torch.empty((tokens,width),dtype=dtype,device=device)
                residual=torch.empty((tokens,4,width),dtype=dtype,device=device)
                out=torch.empty_like(residual)
                post=(torch.arange(tokens*4,device=device).float().reshape(tokens,4)%7+1)/16
                comb=(torch.arange(tokens*16,device=device).float().reshape(tokens,4,4)%11-5)/32
                base=(torch.arange(x.numel(),device=device).reshape(x.shape).float()%17-8)/16
                resbase=(torch.arange(residual.numel(),device=device).reshape(residual.shape).float()%13-6)/16
                def fill(i):
                    delta=(i%4)/16
                    x.copy_((base+rank/8+delta).to(dtype));residual.copy_((resbase+delta).to(dtype))
                    summed=sum((base+r/8+delta).to(dtype).float() for r in range(world)).to(dtype).float()
                    expected=summed[:,None,:]*post[:,:,None]+torch.einsum('mih,mij->mjh',residual.float(),comb)
                    return expected
                paths=['only','one_stage','split'] if width<=4096 else ['split']
                for path in paths:
                    fn=getattr(ops,'fused_allreduce_mhc_post_'+path)
                    def invoke():
                        fn(ca._ptr,x,out,residual,post,comb,True,False,
                           ca._pool['input'].data_ptr,ca._pool['input'].max_size)
                    def check(expected):
                        assert torch.isfinite(out).all()
                        torch.testing.assert_close(out.float(),expected,rtol=tol,atol=tol,
                                                   msg=f'{dtype}/{tokens}x{width}/{path}')
                    ref=fill(0);invoke();check(ref)
                    graph=torch.cuda.CUDAGraph()
                    with torch.cuda.graph(graph):invoke()
                    repeats=5 if tokens==8192 else 100
                    for i in range(repeats):ref=fill(i);graph.replay();check(ref)
                    del graph
                    print('MHC_CASE_PASS',rank,str(dtype),tokens,width,path,repeats,flush=True)
                    count+=1
        # Public allocation wrappers and negative contracts.
        ref=fill(0)
        for fn in (ops.launch_fused_allreduce_mhc_post_only,ops.launch_fused_allreduce_mhc_post_split):
            result=fn(ca._ptr,x,residual,post.unsqueeze(-1),comb,
                      reg_ptr=ca._pool['input'].data_ptr,reg_bytes=ca._pool['input'].max_size)
            torch.testing.assert_close(result.float(),ref,rtol=tol,atol=tol)
        def rejected(**kw):
            args=dict(_fa=ca._ptr,inp=x,next_residual=out,residual_in=residual,post_layer_mix=post,
                      comb_res_mix=comb,reg_ptr=ca._pool['input'].data_ptr,reg_bytes=ca._pool['input'].max_size)
            args.update(kw)
            try:ops.fused_allreduce_mhc_post_one_stage(**args)
            except (RuntimeError,ValueError):return
            raise AssertionError('invalid MHC metadata accepted')
        rejected(next_residual=residual)
        rejected(post_layer_mix=post.to(dtype))
        rejected(open_fp8_quant=True)
        rejected(reg_bytes=16)
        torch.cuda.synchronize();dist.barrier()
        print('AR_MHC_PASS',rank,world,'cases',count,flush=True)
    finally:
        ca.close();dist.destroy_process_group()

if __name__=='__main__':main()
