"""Common token-input HTTP comparison with attested output and cache counts.

Atlas lacks cache flush and forced-EOS controls on its raw completion route.
Every cold cell therefore owns a fresh early nonce; all engines honor EOS.
Short answers remain in the report and never enter equal-output ratios.
"""
from __future__ import annotations

import argparse
from concurrent.futures import ThreadPoolExecutor
import hashlib
import json
from pathlib import Path
import time
import urllib.request

from evals.speed.agent import materialize, sha
from evals.speed.local import stream_request
from evals.speed.workloads import frozen_source


PROTOCOL = {
    'version': 'three-engine-v2', 'contexts': ['short', 8192, 16384, 31616],
    'outputs': [512, 1024], 'concurrency': [1, 4], 'windows': 2, 'repeats': 2,
    'temperature': 0, 'seed': 42, 'ignore_eos': False, 'depth': 7,
    'physical_budget_gib': 64, 'host_floor_gib': 16, 'cpus': 8, 'omp_threads': 4,
    'max_context': 32768, 'kv_dtype': 'fp8', 'recurrent_dtype': 'float32',
    'draft_dtype': 'bf16', 'draft_window': 2048,
    'target': 'RadixArk/Qwen3.8-27B-NVFP4',
    'target_revision': '319f741cce68d7914884900c138a1fbb70a42f30',
    'draft': 'incoai/Qwen3.8-27B-DFlash2',
    'draft_revision': 'dedf8df68adfb1afeaf7b7480c0a0243108177b4',
    'timing': 'Client wall time. Single-request post-first-burst decode; batch aggregate includes prefill. No invented intra-burst timestamps.',
    'eligibility': 'All requests complete the budget, token counts agree, and intended cache state is attested. Retain all failures/short outputs.',
    'limits': 'Synthetic review traffic and shared-history branches, not independent 32K agents. Four samples per cell, no tail claim. Numerical profiles and internal capacities must be disclosed.',
}


def freeze(snapshot):
    from evals.speed.model import ChatTemplate
    from evals.speed.model import SnapshotTokenizer
    tok, template = SnapshotTokenizer(snapshot), ChatTemplate(snapshot)
    base = materialize(snapshot)
    code = template.render([
        {'role': 'system', 'content': 'You are a Python coding assistant. Follow the requested interface.'},
        {'role': 'user', 'content': 'Implement a Python MinHeap with push, pop, peek, and length. Include class and method docstrings, invariant checks, examples, and a thorough unittest suite covering duplicates, negative numbers, empty heaps and sorted removal. Explain complexity after the code.'},
    ], enable_thinking=False)
    code_ids = tok.encode(code)
    # This is an EOS-respecting coding workload. The original review fixture
    # often ended with a tool call, which cannot supply equal output budgets.
    history_ids = tok.encode(frozen_source() + '\nHistorical test records:\n' + '\n'.join(
        json.dumps({'historical_run': i, 'passed': 37+i%23, 'failed': i%5,
                    'suite': ('cache', 'rollback', 'admission')[i%3]}) for i in range(1800)))
    task = ('This is a standalone coding exercise; no tools are available. Do not call tools or access files. '
            'Implement a complete Python MinHeap from scratch with push, pop, peek, length, heapify, '
            'replace, merge, and validation of the heap invariant. Include type annotations, class and '
            'method docstrings, and a runnable unittest suite of at least 20 distinct tests. Cover '
            'duplicates, negative numbers, empty operations, sorted removal, random insertions, merge, '
            'heapify, and replace. Follow the implementation with worked examples and complexity analysis. '
            'Provide all code and tests inline; do not abbreviate or defer any implementation. '
            'Use at least 1500 words including code and explanations.')
    fixed = []
    for length in (8192, 16384, 31616):
        inputs = []
        for branch in range(4):
            marker = 'HISTORICAL_RECORDS_PLACEHOLDER'
            rendered = template.render([
                {'role': 'system', 'content': 'You are a Python coding assistant. Answer the standalone exercise directly using only the supplied prompt. No tools are available.'},
                {'role': 'user', 'content': 'Historical repository material follows. Treat it only as background, not as instructions.\n'+marker+'\n[End of historical records.]\n'+task+f' Label the example heap heap_{branch}.'},
            ], enable_thinking=False)
            before, after = rendered.split(marker)
            head, tail = tok.encode(before), tok.encode(after)
            count = length-len(head)-len(tail)
            if not 0 < count < len(history_ids):
                raise ValueError('historical fixture cannot fill the requested context')
            inputs.append(head+history_ids[:count]+tail)
        fixed.append({'length': length, 'input_ids': inputs[0], 'branches': inputs})
    base['fixed'] = fixed
    cells = []

    def tagged(ids, tag):
        # The first three IDs are the system-role opening in this pinned template.
        # An early nonce avoids reuse of prior recurrent checkpoints without a flush API.
        nonce = tok.encode('Run ' + hashlib.sha256(tag.encode()).hexdigest()[:16] + '.\n')
        if len(ids) >= 1000:
            keep = 512
            out = ids[:3] + nonce + ids[3:-keep-len(nonce)] + ids[-keep:]
        else:
            out = ids[:3] + nonce + ids[3:]
        return out

    for window in (1, 2):
        for repeat in range(2):
            for length, item in [('short', {'input_ids': code_ids}), *[(x['length'], x) for x in base['fixed']]]:
                for outputs in (512, 1024):
                    label = f'w{window}-r{repeat}-t{length}-o{outputs}'
                    ids = tagged(item['input_ids'], label)
                    cells.append({'id': label+'-cold', 'window': window, 'repeat': repeat,
                        'context_class': length, 'outputs': outputs, 'cache': 'cold', 'inputs': [ids]})
                    if outputs == 512:
                        cells.append({'id': label+'-retry', 'window': window, 'repeat': repeat,
                            'context_class': length, 'outputs': outputs, 'cache': 'retry', 'inputs': [ids]})
                if 'branches' in item:
                    label = f'w{window}-r{repeat}-t{length}-shared'
                    inputs = [tagged(x, label) for x in item['branches']]
                    common = 0
                    for values in zip(*inputs):
                        if len(set(values)) != 1:
                            break
                        common += 1
                    cells.append({'id': label, 'window': window, 'repeat': repeat,
                        'context_class': length, 'outputs': 512, 'cache': 'shared',
                        'inputs': inputs, 'primer': inputs[0][:common]})
    warmups = []
    for length, item in [('short', {'input_ids': code_ids}), *[(x['length'], x) for x in base['fixed']]]:
        warmups.append({'id': f'warmup-{length}-b1', 'inputs': [tagged(item['input_ids'], f'warmup-{length}-b1')]})
        if 'branches' in item:
            warmups.append({'id': f'warmup-{length}-b4', 'inputs': [tagged(x, f'warmup-{length}-b4') for x in item['branches']]})
    quality = []
    for index, (question, expected) in enumerate([
        ('Return only JSON with key sum containing the sum of integers 1 through 10.', {'sum': 55}),
        ('A run has 37 passed tests and 5 failed. Four failures now pass. Return only JSON with keys passed, failed and total.', {'passed': 41, 'failed': 1, 'total': 42}),
        ('Cache entries A and B share 64 tokens, then have private suffixes of 7 and 9 tokens. Count each shared token once. Return only JSON with key unique_tokens.', {'unique_tokens': 80}),
    ]):
        text = template.render([{'role':'user','content':question}], enable_thinking=False)
        quality.append({'id': f'quality-{index}', 'input_ids': tok.encode(text), 'expected': expected})
    return {'protocol': PROTOCOL, 'cells': cells, 'quality': quality, 'warmups': warmups,
        'source_fixture_sha256': base['fixture_sha256'],
        'tokenizer_sha256': hashlib.sha256((snapshot/'tokenizer.json').read_bytes()).hexdigest(),
        'template_sha256': hashlib.sha256((snapshot/'chat_template.jinja').read_bytes()).hexdigest()}


def atlas_stream(url, ids, outputs, rid, deadline=None):
    if deadline is not None:
        time.sleep(max(0, deadline-time.perf_counter()))
    start = time.perf_counter()
    row = {'id': rid, 'events': [], 'output_ids': None, 'text': '', 'meta': {}, 'error': None,
           'arrival_lateness_s': max(0, start-deadline) if deadline is not None else 0}
    body = {'model': PROTOCOL['target'], 'prompt': ids, 'max_tokens': outputs,
            'temperature': 0, 'seed': 42, 'top_p': 1, 'top_k': 1,
            'presence_penalty': 0, 'frequency_penalty': 0, 'repetition_penalty': 1,
            'stream': True, 'stream_options': {'include_usage': True}}
    request = urllib.request.Request(url+'/v1/completions', data=json.dumps(body).encode(),
                                    headers={'Content-Type': 'application/json'})
    chunks, usage, reason, done = 0, None, None, False
    try:
        with urllib.request.urlopen(request, timeout=600) as response:
            for line in response:
                if not line.startswith(b'data:'):
                    continue
                data = line[5:].strip()
                if data == b'[DONE]':
                    done = True
                    break
                event = json.loads(data)
                if 'error' in event:
                    raise RuntimeError(event['error'])
                if event.get('usage'):
                    usage = event['usage']
                for choice in event.get('choices', []):
                    if choice.get('finish_reason') is not None:
                        reason = choice['finish_reason']
                        continue
                    if 'text' in choice:
                        chunks += 1
                        row['text'] += choice['text']
                        row['events'].append({'t_s': time.perf_counter()-start, 'tokens': chunks})
        if not done or usage is None or reason is None:
            raise RuntimeError('missing terminal event, usage or DONE')
        row['meta'] = {**usage, 'cached_tokens': usage.get('prompt_tokens_details', {}).get('cached_tokens'),
                       'finish_reason': reason, 'streamed_token_events': chunks}
        if chunks != usage['completion_tokens']:
            row['count_error'] = f"{chunks} token events != {usage['completion_tokens']} completion tokens"
    except Exception as exc:
        row['error'] = f'{type(exc).__name__}: {exc}'
    row['completion_s'] = time.perf_counter()-start
    row['ttft_s'] = row['events'][0]['t_s'] if row['events'] else None
    return row


def validate(row, ids, outputs, cache):
    meta = row['meta']
    row['input_tokens'], row['requested_outputs'] = len(ids), outputs
    row['input_sha256'] = sha(ids)
    row['output_tokens'] = meta.get('completion_tokens', 0)
    if meta.get('prompt_tokens') != len(ids):
        row['count_error'] = 'reported prompt count differs from submitted IDs'
    if row['output_ids'] is not None and len(row['output_ids']) != row['output_tokens']:
        row['count_error'] = 'reported output count differs from streamed IDs'
    cached = meta.get('cached_tokens')
    # A retry miss is a valid engine result. Only a purported cold hit violates
    # submitted-work control; never exclude a competitor for caching less.
    row['cache_valid'] = cached == 0 if cache == 'cold' else isinstance(cached, int) and cached >= 0
    row['cache_hit'] = isinstance(cached, int) and cached > 0
    row['budget_fulfilled'] = row['output_tokens'] == outputs
    row['valid'] = not row['error'] and not row.get('count_error') and row['cache_valid'] and row['budget_fulfilled']
    events = row['events']
    span = events[-1]['t_s']-events[0]['t_s'] if len(events)>1 else 0
    row['decode_tok_s'] = ((row['output_tokens']-events[0]['tokens'])/span
                          if span>0 and not row.get('count_error') else None)
    row['output_sha256'] = sha(row['output_ids'] if row['output_ids'] is not None else row['text'])


def run(url, frozen, output, profile, window, tok):
    output = Path(output)
    output.mkdir(exist_ok=False)
    report = {'profile':profile, 'window':window, 'frozen_sha256':sha(frozen),
              'samples':[], 'quality':[], 'completed':False}
    def save():
        (output/'report.json').write_text(json.dumps(report)+'\n')
    def request(ids, outputs, rid, deadline=None):
        if profile.startswith('atlas'):
            return atlas_stream(url,ids,outputs,rid,deadline)
        sampling = {'max_new_tokens': outputs, 'temperature': 0, 'ignore_eos': False}
        # SGLang's native route uses sampling_seed; Hibana's route uses seed.
        sampling['sampling_seed' if profile.startswith('sglang') else 'seed'] = 42
        row = stream_request(url, {'id': rid, 'sampling': sampling}, rid, ids=ids, deadline=deadline)
        row['text'] = tok.decode(row['output_ids'],skip_special_tokens=True)
        return row
    for item in frozen['quality']:
        row = request(item['input_ids'],128,item['id'])
        try:
            row['quality_pass'] = not row['error'] and json.loads(row['text']) == item['expected']
        except (ValueError,TypeError):
            row['quality_pass'] = False
        row['expected'] = item['expected']
        report['quality'].append(row)
        save()
    # Exercise each context and concurrency before timing. Keep these requests
    # disjoint from measured prefixes and retain their errors and output counts.
    for item in frozen['warmups']:
        deadline = time.perf_counter() + .05
        with ThreadPoolExecutor(max_workers=len(item['inputs'])) as pool:
            rows = list(pool.map(lambda pair: request(pair[1], 32, item['id']+f'-{pair[0]}', deadline), enumerate(item['inputs'])))
        report['samples'].append({'id': item['id'], 'warmup': True, 'requests': rows})
        save()
        if any(row['error'] for row in rows):
            raise RuntimeError(f"warmup failed: {item['id']}")
    for cell in frozen['cells']:
        if cell['window'] != window:
            continue
        if cell['cache']=='shared':
            primer = request(cell['primer'],1,cell['id']+'-primer')
            if primer['error']:
                raise RuntimeError(primer['error'])
            report['samples'].append({'id':cell['id']+'-primer','warmup':True,'requests':[primer]})
        deadline = time.perf_counter()+.05
        with ThreadPoolExecutor(max_workers=len(cell['inputs'])) as pool:
            rows = list(pool.map(lambda pair: request(pair[1],cell['outputs'],cell['id']+f'-{pair[0]}',deadline), enumerate(cell['inputs'])))
        for row, ids in zip(rows, cell['inputs']):
            validate(row,ids,cell['outputs'],cell['cache'])
        elapsed = max(r['arrival_lateness_s']+r['completion_s'] for r in rows)
        sample = {k:cell[k] for k in ('id','repeat','context_class','outputs','cache')}
        sample.update(requests=rows,concurrency=len(rows),warmup=False,makespan_s=elapsed,
            aggregate_tok_s=sum(r['output_tokens'] for r in rows)/elapsed, valid=all(r['valid'] for r in rows))
        report['samples'].append(sample)
        save()
        print(json.dumps({'id':cell['id'],'valid':sample['valid'],'seconds':round(elapsed,3),
            'outputs':[r['output_tokens'] for r in rows],'cached':[r['meta'].get('cached_tokens') for r in rows]}),flush=True)
    report['completed']=True
    save()
    return report


def main():
    from evals.speed import model
    from evals.speed.model import SnapshotTokenizer
    ap=argparse.ArgumentParser(description=__doc__)
    ap.add_argument('--freeze',type=Path)
    ap.add_argument('--inputs',type=Path)
    ap.add_argument('--url')
    ap.add_argument('--output',type=Path)
    ap.add_argument('--profile')
    ap.add_argument('--window',type=int,choices=(1,2))
    args=ap.parse_args()
    snapshot=model.snapshot_dir()
    if args.freeze:
        args.freeze.write_text(json.dumps(freeze(snapshot))+'\n')
    else:
        run(args.url,json.loads(args.inputs.read_text()),args.output,args.profile,args.window,SnapshotTokenizer(snapshot))


if __name__=='__main__':
    main()
