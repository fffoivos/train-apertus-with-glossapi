#!/usr/bin/env python3
"""Trainer-side label inspection (astra gate-2 F6): render rows with the trainer's own tokenize_messages and print which assistant turns are supervised.
Run on the cluster in the sft5 env: python cluster/inspect_labels.py --config cluster/configs/R4_full.yaml --train data/arms/R4_full/train.jsonl"""
import argparse, json, sys, os
sys.path.insert(0, os.path.dirname(os.path.abspath(__file__))); import sft_train as T
ap = argparse.ArgumentParser(); ap.add_argument('--config', required=True); ap.add_argument('--train', required=True); a = ap.parse_args()
config = T.load_config(a.config); tok = T.prepare_tokenizer(config); tok = tok[0] if isinstance(tok, tuple) else tok
want = {'format_mc': lambda r: sum(1 for m in r['messages'] if m['role'] == 'assistant') >= 3, 'correcting_v2': lambda r: any(m.get('train') is False for m in r['messages']), 'convskills_v2': lambda r: any(m.get('train') is False for m in r['messages']), 'greek_math_v2': lambda r: True}
picked = {}
for l in open(a.train):
    r = json.loads(l); c = r['config']
    if c in want and c not in picked and want[c](r): picked[c] = r
    if len(picked) == len(want): break
for c, r in picked.items():
    out = T.tokenize_messages(tok, r['messages']); ids, labels = out['input_ids'], out['labels']
    n_sup = sum(1 for x in labels if x != -100); spans = []; cur = []
    for i, (t, lab) in enumerate(zip(ids, labels)):
        if lab != -100: cur.append(t)
        elif cur: spans.append(tok.decode(cur)); cur = []
    if cur: spans.append(tok.decode(cur))
    flags = [(m.get('train', True)) for m in r['messages'] if m['role'] == 'assistant']
    print(f"=== {c} {r['id']}: {len(ids)} tokens, {n_sup} supervised; assistant turns {len(flags)}, flagged train=false {flags.count(False)}; supervised spans {len(spans)}")
    for k, sp in enumerate(spans): print(f"   span {k}: {sp[:160]!r}")
