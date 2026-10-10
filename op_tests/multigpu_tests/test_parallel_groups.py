"""Four-rank group layout, public collective, coexistence and reinit contracts."""
import os
import torch
import torch.distributed as dist
import aiter
from aiter.dist import parallel_state as ps, communication_op as comm


def main():
    # Each global reinit owns a fresh TCPStore, independent of torchrun's agent.
    os.environ['TORCHELASTIC_USE_AGENT_STORE'] = 'False'
    rank, local = (int(os.environ[k]) for k in ('RANK', 'LOCAL_RANK'))
    torch.cuda.set_device(local)
    device = torch.device('cuda', local)
    # Fixed expected lists deliberately independent of implementation reshapes.
    cases = [
        (dict(tp=2, dp=2, pp=1, pcp=1, dcp=2),
         dict(tp=[[0,1],[2,3]],dp=[[0,2],[1,3]],pp=[[0],[1],[2],[3]],
              ep=[[0,1,2,3]],pcp=[[0],[1],[2],[3]],dcp=[[0,1],[2,3]])),
        (dict(tp=2, dp=1, pp=2, pcp=1, dcp=1),
         dict(tp=[[0,1],[2,3]],dp=[[0],[1],[2],[3]],pp=[[0,2],[1,3]],
              ep=[[0,1],[2,3]],pcp=[[0],[1],[2],[3]],dcp=[[0],[1],[2],[3]])),
        (dict(tp=2, dp=1, pp=1, pcp=2, dcp=2),
         dict(tp=[[0,1],[2,3]],dp=[[0],[1],[2],[3]],pp=[[0],[1],[2],[3]],
              ep=[[0,1,2,3]],pcp=[[0,2],[1,3]],dcp=[[0,1],[2,3]])),
    ]
    for index,(cfg,expected) in enumerate(cases):
        inner=cfg['tp']*cfg['pp']*cfg['pcp']
        # Exercise the legacy positional entry and new named TP argument.
        args=dict(backend='nccl',local_rank=local,data_parallel_size=cfg['dp'],
                  distributed_init_method=f'tcp://127.0.0.1:{29885+index}',
                  data_parallel_rank=rank//inner,pipeline_model_parallel_size=cfg['pp'],
                  prefill_context_model_parallel_size=cfg['pcp'],decode_context_parallel_size=cfg['dcp'],
                  custom_group_config={'pair':[[0,3],[1,2]]})
        if index==0:aiter.init_dist_env(cfg['tp'],rank%inner,**args)
        else:aiter.init_dist_env(rankID=rank%inner,tensor_model_parallel_size=cfg['tp'],**args)
        for name,groups in expected.items():
            group=getattr(ps,'get_'+name+'_group')()
            assert group.ranks==next(g for g in groups if rank in g),(name,rank,group.ranks)
            x=torch.full((4,8),rank+1.,device=device)
            y=group.all_reduce(x)
            torch.testing.assert_close(y,torch.full_like(x,sum(r+1 for r in group.ranks)))
        for name,prefix in [('dp','data_parallel'),('ep','expert_parallel'),('pp','pipeline_model_parallel')]:
            group=getattr(ps,'get_'+name+'_group')()
            def value():return torch.full((4,8),rank+1.,device=device)
            y=getattr(comm,prefix+'_all_reduce')(value())
            torch.testing.assert_close(y,torch.full_like(y,sum(r+1 for r in group.ranks)))
            y=getattr(comm,prefix+'_all_gather')(value(),dim=1)
            ref=torch.cat([torch.full((4,8),r+1.,device=device) for r in group.ranks],1)
            torch.testing.assert_close(y,ref)
            y=getattr(comm,prefix+'_broadcast')(value())
            torch.testing.assert_close(y,torch.full_like(y,group.ranks[0]+1.))
            payload={'x':value(),'tag':'sync'} if group.rank_in_group==0 else None
            result=getattr(comm,prefix+'_broadcast_tensor_dict')(payload)
            assert result['tag']=='sync'
            torch.testing.assert_close(result['x'],torch.full((4,8),group.ranks[0]+1.,device=device))
            if name!='pp':
                y=getattr(comm,prefix+'_reduce_scatter')(value(),use_custom=False,dim=1)
                torch.testing.assert_close(y,torch.full((4,8//group.world_size),sum(r+1. for r in group.ranks),device=device))
                y=getattr(comm,prefix+'_gather')(value(),dim=1)
                if group.rank_in_group==0:torch.testing.assert_close(y,ref)
                else:assert y is None
            elif group.world_size==2:
                if group.rank_in_group==0:comm.pipeline_model_parallel_send(value(),dst=1)
                else:
                    y=comm.pipeline_model_parallel_recv(torch.Size((4,8)),torch.float32,src=0)
                    torch.testing.assert_close(y,torch.full_like(y,group.ranks[0]+1.))
        torch._dynamo.reset()
        compiled=torch.compile(comm.data_parallel_all_reduce,backend='eager',fullgraph=True)
        group=ps.get_dp_group()
        y=compiled(torch.full((4,8),rank+1.,device=device))
        torch.testing.assert_close(y,torch.full_like(y,sum(r+1 for r in group.ranks)))
        custom=ps.get_custom_group('pair')
        y=custom.all_reduce(torch.full((4,8),rank+1.,device=device))
        torch.testing.assert_close(y,torch.full_like(y,sum(r+1 for r in custom.ranks)))
        # Global graph context includes new groups; DP uses the RCCL communicator.
        x=torch.full((4,8),rank+1.,device=device)
        group=ps.get_dp_group()
        with ps.graph_capture() as context:
            comm.data_parallel_all_reduce(x)
            graph=torch.cuda.CUDAGraph()
            with torch.cuda.graph(graph,stream=context.stream):y=comm.data_parallel_all_reduce(x)
        for step in range(10):
            x.fill_(rank+1.+step);graph.replay()
            torch.testing.assert_close(y,torch.full_like(y,sum(r+1.+step for r in group.ranks)))
        del graph
        torch.cuda.synchronize();dist.barrier()
        aiter.destroy_dist_env()
        assert not ps.model_parallel_is_initialized()
        print('GROUP_CASE_PASS',rank,index,flush=True)
    print('GROUP_CONTRACTS_PASS',rank,flush=True)


if __name__=='__main__':main()
