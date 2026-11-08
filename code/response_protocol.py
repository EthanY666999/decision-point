"""Opt-in first complete action block protocol for future no-SFT runs.

Only sampled token prefixes are retained. No retokenization or synthetic
training target is permitted. The chat EOS added after a cutoff is context
only, with mask and old_logprob zero.
"""
import hashlib
import re
from types import MethodType, SimpleNamespace

NAME = 'first_complete_action_block'
BLOCK = re.compile(r'```\s*(left|down|right|up|[1-4])\s*```', re.I)
ACTIONS = dict(left=1, down=2, right=3, up=4)

def first_block(text):
    return BLOCK.search(text)

def parse_first_block(self, response):
    match = first_block(response)
    if match is None:
        return response, '0'
    word = match.group(1).lower()
    action = ACTIONS[word] if word in ACTIONS else int(word)
    return response[:match.start()].strip(), str(action)

def configure_agent(agent, cfg):
    if cfg.get('response_protocol') == NAME:
        agent._parse_model_response = MethodType(parse_first_block, agent)

def truncate_response(branch, out, tokenizer):
    # A counterfactual branch may already contain a sampled reasoning/fence
    # prefix for this same turn. Ordinary branches end with mask=0 prompts.
    start = len(branch.ids)
    while start and branch.mask[start-1]:
        start -= 1
    copied = list(branch.ids[start:])
    fresh = list(out.token_ids)
    full = copied + fresh
    text = tokenizer.decode(full, skip_special_tokens=True)
    match = first_block(text)
    if match is None:
        return out, None
    # Stop at the first sampled TOKEN completing the block. A token is atomic:
    # retain and record any characters sharing its closing-fence token.
    endpoint = None
    for n in range(len(copied)+1, len(full)+1):
        prefix = tokenizer.decode(full[:n], skip_special_tokens=True)
        if len(prefix) >= match.end():
            assert prefix.startswith(text[:match.end()])
            endpoint = n
            break
    assert endpoint is not None
    keep = endpoint - len(copied)
    assert keep > 0
    meta = dict(protocol=NAME, retained_sampled_tokens=endpoint,
                discarded_sampled_tokens=len(full)-endpoint,
                discarded_ids_sha256=hashlib.sha256(repr(full[endpoint:]).encode()).hexdigest(),
                context_eos_injected=True, context_eos_trained=False,
                boundary_unit='sampled_token', action_block_character_end=match.end(),
                boundary_token_overhang=prefix[match.end():])
    result = SimpleNamespace(token_ids=fresh[:keep], logprobs=list(out.logprobs[:keep]),
                             text=prefix, finish_reason='stop')
    return result, meta
