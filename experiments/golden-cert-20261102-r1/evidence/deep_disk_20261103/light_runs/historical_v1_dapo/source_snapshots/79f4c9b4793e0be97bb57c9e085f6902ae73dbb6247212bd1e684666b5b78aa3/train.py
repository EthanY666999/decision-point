"""Single-GPU, full-parameter multi-turn RL, with outcome-only group advantages.

The tree policy and GRPO objective follow PaTR; rLLM's environment/agent are used
unchanged. The single-process optimizer/rollout orchestration is a reconstruction,
not the unpublished author's rLLM training patch. See REPRODUCTION_AUDIT.md.
"""
import os
os.environ['VLLM_USE_V1']='0'
os.environ['VLLM_ATTENTION_BACKEND']='FLASH_ATTN'
os.environ['VLLM_USE_FLASHINFER_SAMPLER']='0'
os.environ['TOKENIZERS_PARALLELISM']='false'
os.environ['OMP_NUM_THREADS']='8'
os.environ['VLLM_NO_USAGE_STATS']='1'
os.environ['DO_NOT_TRACK']='1'
os.environ['WANDB_MODE']='offline'

import argparse
import copy
import gzip
import hashlib
import json
import random
import signal
import time
from collections import Counter
from pathlib import Path

import numpy as np
import torch
import torch.nn.functional as F
from torch.utils.checkpoint import checkpoint
from transformers import AutoModelForCausalLM, AutoTokenizer

from patr_core import (ROOT, atomic_json, append_json, make_datasets, collect,
                       evaluation_metrics, training_weights)

STOP=False
RUNTIME_KEYS={'micro_batch_size','micro_batch_token_limit','vllm_memory_fraction','vllm_max_sequences','vllm_enforce_eager','vllm_attention_backend'}


def request_stop(signum, frame):
    global STOP
    STOP=True


def build_models(cfg,seed):
    backend=cfg.get('vllm_attention_backend','FLASH_ATTN')
    assert backend in {'FLASH_ATTN','XFORMERS'},'Unsupported inference attention backend'
    os.environ['VLLM_ATTENTION_BACKEND']=backend
    # Triton builds its Python extension on first use. Minimal host images may
    # omit Python.h; matching distro headers can be extracted without root.
    local_include=ROOT/'artifacts/build-deps/usr/include'
    if (local_include/'python3.12/Python.h').exists():
        include_paths=[str(local_include/'python3.12'),str(local_include)]
        if os.environ.get('C_INCLUDE_PATH'):include_paths.append(os.environ['C_INCLUDE_PATH'])
        os.environ['C_INCLUDE_PATH']=os.pathsep.join(include_paths)
    from vllm import LLM
    torch.set_num_threads(8)
    torch.manual_seed(seed)
    torch.cuda.manual_seed_all(seed)
    random.seed(seed)
    model_path=str(ROOT/cfg['model'])
    tokenizer=AutoTokenizer.from_pretrained(model_path,local_files_only=True)
    tokenizer.pad_token=tokenizer.eos_token
    actor=AutoModelForCausalLM.from_pretrained(model_path,torch_dtype=torch.float32,
                   attn_implementation='sdpa',local_files_only=True).to('cuda')
    actor.gradient_checkpointing_enable(gradient_checkpointing_kwargs={'use_reentrant':False})
    actor.config.use_cache=False
    ref=AutoModelForCausalLM.from_pretrained(model_path,torch_dtype=torch.bfloat16,
                   attn_implementation='sdpa',local_files_only=True).to('cuda').eval()
    ref.requires_grad_(False)
    engine=LLM(model=model_path,tokenizer=model_path,dtype='bfloat16',
               tensor_parallel_size=1,distributed_executor_backend='uni',
               gpu_memory_utilization=cfg['vllm_memory_fraction'],
               max_model_len=cfg['max_context_tokens'],max_num_seqs=cfg['vllm_max_sequences'],
               max_num_batched_tokens=4096,enable_chunked_prefill=True,
               enable_prefix_caching=True,disable_async_output_proc=True,
               seed=seed,enforce_eager=cfg.get('vllm_enforce_eager',False),disable_log_stats=True)
    return actor,ref,engine,tokenizer


def sync_weights(actor,engine):
    # V0/UniProc colocates the inference model. No network service or extra GPU.
    vm=engine.llm_engine.model_executor.driver_worker.model_runner.model
    with torch.no_grad():
        loaded=vm.load_weights((name,p.detach().to(torch.bfloat16)) for name,p in actor.named_parameters())
        assert torch.equal(vm.model.layers[-1].mlp.down_proj.weight,
                           actor.model.layers[-1].mlp.down_proj.weight.to(torch.bfloat16)), 'Inference weight synchronization failed'
    engine.llm_engine.reset_prefix_cache()
    torch.cuda.synchronize()
    return len(loaded) if loaded is not None else None


def selected_logprobs(model,ids,attention,mask,gradient=False):
    """Only allocate vocabulary logits for assistant targets, in bounded chunks."""
    with torch.autocast('cuda',dtype=torch.bfloat16):
        hidden=model.model(input_ids=ids,attention_mask=attention,use_cache=False).last_hidden_state
        keep=mask[:,1:].bool()
        h=hidden[:,:-1][keep]
        labels=ids[:,1:][keep]
        parts=[]
        def head_logprob(x,y):
            with torch.autocast('cuda',dtype=torch.bfloat16):
                logits=model.lm_head(x)
            return -F.cross_entropy(logits.float(),y,reduction='none')
        for lo in range(0,len(labels),512):
            hs,ys=h[lo:lo+512],labels[lo:lo+512]
            lp=checkpoint(head_logprob,hs,ys,use_reentrant=False) if gradient else head_logprob(hs,ys)
            parts.append(lp)
        return torch.cat(parts)


def pack(rows,pad):
    maxlen=max(len(b.ids) for b,_,_ in rows)
    ids=torch.full((len(rows),maxlen),pad,device='cuda',dtype=torch.long)
    attn=torch.zeros_like(ids)
    mask=torch.zeros_like(ids)
    advantages=[];weights=[];old=[]
    for i,(b,a,w) in enumerate(rows):
        n=len(b.ids)
        ids[i,:n]=torch.tensor(b.ids,device='cuda')
        attn[i,:n]=1
        mask[i,:n]=torch.tensor(b.mask,device='cuda')
        advantages.extend([a]*b.ntokens)
        weights.extend([w]*b.ntokens)
        old.extend(v for v,m in zip(b.old_logprobs,b.mask) if m)
    f=lambda x:torch.tensor(x,dtype=torch.float32,device='cuda')
    return ids,attn,mask,f(advantages),f(weights),f(old)


def microbatches(rows,cfg):
    # Sort only within the current optimizer minibatch to reduce padding.
    rows=sorted(rows,key=lambda x:len(x[0].ids))
    batch=[]
    for row in rows:
        if batch and (len(batch)>=cfg['micro_batch_size'] or
                      len(row[0].ids)*(len(batch)+1)>cfg['micro_batch_token_limit']):
            yield batch
            batch=[]
        batch.append(row)
    if batch:
        yield batch


def update(actor,ref,optimizer,branches,cfg,method,tokenizer,rng,n_tasks):
    actor.train()
    metrics=Counter();mb_count=0
    task_order=rng.permutation(n_tasks).tolist()
    for off in range(0,n_tasks,cfg['mini_batch_tasks']):
        chosen=task_order[off:off+cfg['mini_batch_tasks']]
        idmap={old:new for new,old in enumerate(chosen)}
        # Only remap a shallow copy; rollout records retain their original task IDs.
        bs=[]
        for b in branches:
            if b.task_id in idmap:
                c=copy.copy(b);c.task_id=idmap[b.task_id];bs.append(c)
        rows=training_weights(bs,len(chosen),method=='dapo')
        optimizer.zero_grad(set_to_none=True)
        low=cfg['dapo_clip_low'] if method=='dapo' else cfg['clip_low']
        total_loss=0.;before=None
        for chunk in microbatches(rows,cfg):
            ids,attn,mask,adv,weight,old=pack(chunk,tokenizer.pad_token_id)
            with torch.no_grad():
                ref_lp=selected_logprobs(ref,ids,attn,mask)
            current=selected_logprobs(actor,ids,attn,mask,gradient=True)
            ratio=torch.exp(current-old)
            pg=-torch.minimum(ratio*adv,torch.clamp(ratio,1-low,1+cfg['clip_high'])*adv)
            # Low-variance sampled KL against the frozen initial policy.
            logratio=ref_lp-current
            kl=torch.exp(logratio)-logratio-1
            loss=((pg+cfg['kl_coefficient']*kl)*weight).sum()
            if not torch.isfinite(loss):
                raise FloatingPointError('Nonfinite loss; preserving previous checkpoint')
            loss.backward()
            total_loss+=loss.detach().item()
            metrics['kl']+=(kl.detach()*weight).sum().item()
            metrics['clipfrac']+=(((ratio.detach()<1-low)|(ratio.detach()>1+cfg['clip_high'])).float()*weight).sum().item()
            metrics['sampled_surprisal']+=((-current.detach())*weight).sum().item()
            metrics['weighted_response_tokens']+=len(old)
            del ids,attn,mask,adv,weight,old,ref_lp,current,ratio,pg,kl,loss,logratio
        norm=torch.nn.utils.clip_grad_norm_(actor.parameters(),cfg['max_grad_norm'])
        if not torch.isfinite(norm):
            raise FloatingPointError('Nonfinite gradient norm')
        probe=actor.model.layers[-1].mlp.down_proj.weight
        before=probe.detach().clone()
        optimizer.step()
        delta=(probe.detach()-before).abs().max().item()
        metrics['max_parameter_change']=max(metrics['max_parameter_change'],delta)
        metrics['loss']+=total_loss
        metrics['grad_norm']+=float(norm)
        mb_count+=1
    optimizer.zero_grad(set_to_none=True)
    actor.eval()
    for key in ['loss','grad_norm','kl','clipfrac','sampled_surprisal']:
        metrics[key]/=mb_count
    return dict(metrics)


def save_checkpoint(path,actor,optimizer,step,rng,cfg,elapsed):
    path=Path(path)
    path.parent.mkdir(parents=True,exist_ok=True)
    # torch.save handles CUDA tensors; restore maps to CPU before copying to model.
    state={'step':step,'model':actor.state_dict(),'optimizer':optimizer.state_dict(),
           'rng':rng.bit_generator.state,'torch_rng':torch.get_rng_state(),
           'cuda_rng':torch.cuda.get_rng_state_all(),'python_rng':random.getstate(),
           'config':cfg,'elapsed_seconds':elapsed}
    tmp=path.with_suffix('.tmp')
    torch.save(state,tmp)
    tmp.replace(path)


def evaluate(engine,tokenizer,cfg,tasks,out_path,seed,split):
    rng=np.random.default_rng(seed)
    start=time.monotonic()
    branches,stats,_=collect(tasks,engine,tokenizer,cfg,'grpo',rng,evaluation=True)
    metrics=evaluation_metrics(branches,tasks)
    metrics.update(split=split,seconds=time.monotonic()-start,generated_tokens=stats['generated_tokens'])
    atomic_json(out_path,metrics)
    records=Path(out_path).with_suffix('.jsonl')
    with records.open('w') as f:
        for b in branches:
            f.write(json.dumps(dict(task=tasks[b.task_id],lineage=b.lineage,reward=b.reward,
                         terminal=b.terminal,turns=b.turns,response_tokens=b.ntokens,trace=b.trace))+'\n')
    return metrics


def write_rollouts(path,branches,tasks,mode='wt',attempt=None):
    with gzip.open(path,mode) as f:
        for b in branches:
            f.write(json.dumps(dict(task=tasks[b.task_id],lineage=b.lineage,reward=b.reward,
                terminal=b.terminal,ids=b.ids,mask=b.mask,old_logprobs=b.old_logprobs,
                trace=b.trace,resample_attempt=attempt))+'\n')


def main():
    parser=argparse.ArgumentParser()
    parser.add_argument('--method',required=True,choices=['grpo','dapo','arpo','tree_random','patr'])
    parser.add_argument('--config',default='configs/frozenlake_05b.json')
    parser.add_argument('--smoke',action='store_true')
    parser.add_argument('--resume',action='store_true')
    parser.add_argument('--stop-after-step',type=int)
    args=parser.parse_args()
    cfg=json.loads((ROOT/args.config).read_text())
    override_path=ROOT/'artifacts/runtime_override.json'
    if override_path.exists():
        override=json.loads(override_path.read_text())
        assert set(override)<=RUNTIME_KEYS,'Only engineering batch/memory/execution overrides are allowed'
        cfg.update(override)
    if args.smoke:
        cfg.update(steps=1,train_batch_size=4,mini_batch_tasks=4,eval_every=1,save_every=1,
                   max_response_tokens=1024)
    seed=cfg['seed']
    out=ROOT/'runs'/('smoke' if args.smoke else 'formal')/f'{args.method}_seed{seed}'
    out.mkdir(parents=True,exist_ok=True)
    source_files={name:(ROOT/name).read_bytes() for name in ('train.py','patr_core.py')}
    source_hash=hashlib.sha256(b''.join(source_files.values())).hexdigest()
    snapshot=out/'source_snapshots'/source_hash
    snapshot.mkdir(parents=True,exist_ok=True)
    for name,content in source_files.items():(snapshot/name).write_bytes(content)
    append_json(out/'source_versions.jsonl',dict(sha256=source_hash,unix=time.time(),resume=args.resume))
    atomic_json(out/'config.json',dict(cfg,method=args.method))
    atomic_json(out/'status.json',dict(status='initializing',method=args.method,step=0,total_steps=cfg['steps'],pid=os.getpid()))
    data=make_datasets()
    actor,ref,engine,tokenizer=build_models(cfg,seed)
    optimizer=torch.optim.AdamW(actor.parameters(),lr=cfg['learning_rate'],betas=(.9,.999),eps=1e-8,weight_decay=0.)
    rng=np.random.default_rng(seed)
    start_step=0;previous_elapsed=0.
    cp=out/'checkpoint.pt'
    if args.resume and cp.exists():
        state=torch.load(cp,map_location='cpu',weights_only=False)
        assert {k:v for k,v in state['config'].items() if k not in RUNTIME_KEYS}=={k:v for k,v in cfg.items() if k not in RUNTIME_KEYS},'Cannot resume after an algorithm configuration change'
        actor.load_state_dict(state['model']);optimizer.load_state_dict(state['optimizer'])
        start_step=state['step'];rng.bit_generator.state=state['rng']
        torch.set_rng_state(state['torch_rng']);torch.cuda.set_rng_state_all(state['cuda_rng']);random.setstate(state['python_rng'])
        previous_elapsed=state.get('elapsed_seconds',0.)
        del state
        sync_weights(actor,engine)
        print(json.dumps({'RESUMED':start_step,'checkpoint':str(cp)}),flush=True)
    signal.signal(signal.SIGTERM,request_stop)
    signal.signal(signal.SIGINT,request_stop)
    os.environ['PATR_PROGRESS_PATH']=str(out/'progress.json')
    # Freeze test use to final evaluation. Training curves use a separate validation set.
    validation=data['validation'][:4] if args.smoke else data['validation']
    if start_step==0:
        base=evaluate(engine,tokenizer,cfg,validation,out/'validation_0000.json',100042,'validation')
        print(json.dumps({'initial_validation':base}),flush=True)
    start=time.monotonic()
    step=start_step
    for step in range(start_step+1,cfg['steps']+1):
        deadline_file=ROOT/'artifacts/deadline.json'
        deadline=json.loads(deadline_file.read_text())['unix'] if deadline_file.exists() else float('inf')
        if STOP or time.time()>=deadline:
            step-=1
            break
        atomic_json(out/'status.json',dict(status='training',method=args.method,step=step-1,
                      current_step=step,total_steps=cfg['steps'],pid=os.getpid()))
        t0=time.monotonic()
        # Keep the task stream independent of method-specific branching RNG consumption.
        task_rng=np.random.default_rng(np.random.SeedSequence([seed,step,1701]))
        task_indices=task_rng.choice(len(data['train']),cfg['train_batch_size'],replace=False).tolist()
        tasks=[data['train'][i] for i in task_indices]
        branches,stats,events=collect(tasks,engine,tokenizer,cfg,args.method,rng)
        if args.method=='dapo':
            # Rejection sampling of zero-variance prompt groups; charge all rejected rollout work.
            accepted=[];accepted_tasks=[];attempts=1
            while True:
                write_rollouts(out/f'dapo_candidates_{step:04d}.jsonl.gz',branches,tasks,
                               'wt' if attempts==1 else 'at',attempts)
                groups={ti:[b for b in branches if b.task_id==ti] for ti in range(len(tasks))}
                for ti,task in enumerate(tasks):
                    bs=groups[ti]
                    if len({b.reward for b in bs})>1 and len(accepted_tasks)<cfg['train_batch_size']:
                        for b in bs:b.task_id=len(accepted_tasks)
                        accepted.extend(bs);accepted_tasks.append(task)
                if len(accepted_tasks)==cfg['train_batch_size']:
                    break
                if attempts>=cfg['dapo_max_resample_batches']:
                    raise RuntimeError('DAPO dynamic sampling could not fill batch; no silent fallback')
                tasks=[data['train'][i] for i in task_rng.choice(len(data['train']),cfg['train_batch_size'],replace=False)]
                branches,more,ev=collect(tasks,engine,tokenizer,cfg,'dapo',rng)
                n0,n1=stats['episodes'],more['episodes']
                for k in ['success_rate','mean_response_tokens','mean_turns']:
                    stats[k]=(stats[k]*n0+more[k]*n1)/(n0+n1)
                stats['terminal_counts']=dict(Counter(stats['terminal_counts'])+Counter(more['terminal_counts']))
                for k in ['generated_tokens','input_tokens','episodes','executed_actions','invalid_actions']:stats[k]+=more[k]
                stats['invalid_action_fraction']=stats['invalid_actions']/stats['executed_actions'] if stats['executed_actions'] else None
                events.extend(ev);attempts+=1
            branches=accepted;tasks=accepted_tasks
            stats['resample_batches']=attempts
            stats['accepted_success_rate']=float(np.mean([b.reward>0 for b in branches]))
        sampled_time=time.monotonic()-t0
        atomic_json(out/'progress.json',dict(phase='optimization',method=args.method,step=step,
                      trajectories=len(branches),updated_unix=time.time()))
        optimizer_rng=np.random.default_rng(np.random.SeedSequence([seed,step,1702]))
        changes=update(actor,ref,optimizer,branches,cfg,args.method,tokenizer,optimizer_rng,len(tasks))
        sync_weights(actor,engine)
        elapsed=previous_elapsed+time.monotonic()-start
        record=dict(step=step,method=args.method,seed=seed,rollout_seconds=sampled_time,
                    resumed_from_step=start_step,
                    step_seconds=time.monotonic()-t0,elapsed_seconds=elapsed,
                    peak_allocated_gib=torch.cuda.max_memory_allocated()/2**30,
                    time_utc=time.strftime('%Y-%m-%dT%H:%M:%SZ',time.gmtime()),**stats,**changes)
        append_json(out/'train_metrics.jsonl',record)
        append_json(out/'branch_events.jsonl',dict(step=step,events=events))
        # Preserve complete raw sampled trajectories for auditing, including failures/pruning.
        write_rollouts(out/f'rollouts_{step:04d}.jsonl.gz',branches,tasks)
        print(json.dumps(record),flush=True)
        atomic_json(out/'status.json',dict(status='training',method=args.method,step=step,total_steps=cfg['steps'],pid=os.getpid(),last=record))
        # Protect the first completed update before the regular save interval.
        if step==1 or step%cfg['save_every']==0 or step==cfg['steps']:
            save_checkpoint(cp,actor,optimizer,step,rng,cfg,elapsed)
        if step%cfg['eval_every']==0 or step==cfg['steps']:
            m=evaluate(engine,tokenizer,cfg,validation,out/f'validation_{step:04d}.json',100042,'validation')
            print(json.dumps({'validation_step':step,**m}),flush=True)
        if args.stop_after_step and step>=args.stop_after_step:
            break
    # A checkpoint at step 400 may still have final evaluation pending. Respect
    # the run window before starting that separate, full 100 x 4 evaluation.
    deadline_file=ROOT/'artifacts/deadline.json'
    deadline=json.loads(deadline_file.read_text())['unix'] if deadline_file.exists() else float('inf')
    if step<cfg['steps'] or STOP or time.time()>=deadline:
        save_checkpoint(cp,actor,optimizer,step,rng,cfg,previous_elapsed+time.monotonic()-start)
        atomic_json(out/'status.json',dict(status='paused_checkpointed',step=step,total_steps=cfg['steps'],method=args.method,
                    final_evaluation_pending=step==cfg['steps']))
        return
    tests=data['validation'][4:8] if args.smoke else data['test']
    final=evaluate(engine,tokenizer,cfg,tests,out/'final_test.json',200042,'smoke_validation' if args.smoke else 'test')
    actor.save_pretrained(out/'final_model',safe_serialization=True)
    tokenizer.save_pretrained(out/'final_model')
    atomic_json(out/'status.json',dict(status='smoke_complete' if args.smoke else 'complete',step=step,total_steps=cfg['steps'],method=args.method,final=final))
    print(json.dumps({'FINAL':final}),flush=True)


if __name__=='__main__':
    main()
