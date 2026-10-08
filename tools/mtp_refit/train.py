"""Train the dense part of the MTP layer against the served target (#97, design 4.6).

    python -m tools.mtp_refit.train \
      --snapshot <f4..03> --draft-vocab /opt/mtp-vocab/ids-v2-K131072.txt.gz \
      --data data/train --heldout data/heldout \
      --trainable dense --depth 6 --depth-weights equal --loss kl --topk 20 \
      --window 2048 --lr 2e-5 --warmup 20 --epochs 2 --tokens-per-step 8192 --out runs/<name>

Writes runs/<name>/mtp_refit.safetensors (the trainable tensors, BF16, checkpoint names), train.jsonl
(per optimizer step: soft CE and KL per depth, anchors per depth, lr) and eval.json (offline acceptance
before and after, eval_offline.py), and with --save-every N a ckpt-stepNNNNNN.safetensors every N steps
(same layout as the final file, so eval_offline --refit and splice.py take it). --epochs 0 exports the loaded tensors unchanged. --metrics-file
rewrites a Prometheus textfile (prom.py) after every step and eval, for the #97 dashboard.
"""
from __future__ import annotations

import argparse
import json
import os
import time

import torch

from . import prom
from .assemble import iter_windows
from .eval_offline import evaluate
from .mtp_ref import depth_targets, export, full_to_draft, load_mtp_ref, trainable_names, window_loss


def depth_weights(spec: str, depth: int) -> list[float]:
    if spec == "equal":
        return [1.0] * depth
    if spec.startswith("decay"):
        r = float(spec.partition(":")[2] or 0.6)
        return [r**k for k in range(depth)]
    raise ValueError(f"--depth-weights {spec}: equal or decay[:r]")


@torch.no_grad()
def target_entropy(w, depth, lookup) -> list[float]:
    """Per depth: sum over valid anchors of the entropy of the target top-k as soft_ce sees it
    (renormalized top-k, ids outside the draft vocab dropped). soft CE - this = KL to the target."""
    out = []
    for rows, valid in depth_targets(w["tokens"].shape[0], depth, w["loss_mask"]):
        lp = w["topk_logprobs"][rows[valid]].float().log_softmax(-1)
        p = lp.exp() * (lookup[w["topk_ids"][rows[valid]].long()] >= 0)
        out.append(float(-(p * lp).sum()))
    return out


def step_samples(rec, labels, weights, epochs, anchors_per_s, gpu_mem):
    yield "mtp_refit_train_step", labels, rec["step"]
    yield "mtp_refit_train_epoch", labels, rec["epoch"] + 1
    yield "mtp_refit_train_epochs", labels, epochs
    yield "mtp_refit_train_lr", labels, rec["lr"]
    yield "mtp_refit_train_grad_norm", labels, rec["grad_norm"]
    yield "mtp_refit_train_anchors_per_second", labels, anchors_per_s
    yield "mtp_refit_train_gpu_memory_bytes", labels, gpu_mem
    ce = [(c, wt) for c, wt in zip(rec["ce"], weights) if c is not None]
    yield "mtp_refit_train_loss", labels, sum(c * wt for c, wt in ce) / sum(wt for _, wt in ce) if ce else None
    for k, (c, kl) in enumerate(zip(rec["ce"], rec["kl"])):
        yield "mtp_refit_train_ce", {**labels, "position": k + 1}, c
        yield "mtp_refit_train_kl", {**labels, "position": k + 1}, kl


def train(a) -> dict:
    torch.manual_seed(a.seed)
    model = load_mtp_ref(a.snapshot, a.draft_vocab, a.device, a.trainable, a.experts_impl)
    model.kv_fp8 = getattr(a, "kv_fp8", "on") == "on"
    names = trainable_names(model, a.trainable)
    params = [p for n, p in model.named_parameters() if n in set(names)]
    print(f"trainable: {len(names)} tensors, {sum(p.numel() for p in params) / 1e6:.1f}M params")
    os.makedirs(a.out, exist_ok=True)
    meta = {k: v for k, v in vars(a).items() if k != "func"}
    res = {"args": meta}
    labels = {"run": os.path.basename(os.path.normpath(a.out)), "phase": "train"}
    last = []  # the latest step's samples, rewritten with every eval

    def publish():
        if a.metrics_file:
            evs = [s for when in ("before", "after") if when in res
                   for s in prom.acceptance(res[when], {**labels, "drafter": when})]
            prom.write(a.metrics_file, [*last, *evs])
    stride = a.window_stride or a.window // 2
    ev = dict(depth=a.depth, window=a.window, stride=stride, max_windows=a.eval_windows, device=a.device)
    if a.heldout and a.eval_windows:
        res["before"] = evaluate(model, a.heldout, **ev)
        publish()
    if a.epochs:
        weights = depth_weights(a.depth_weights, a.depth)
        lookup = full_to_draft(model.draft_ids, model.cfg.vocab_size)
        opt = torch.optim.AdamW(params, lr=a.lr, betas=(0.9, 0.95), weight_decay=0.0)
        log = open(os.path.join(a.out, "train.jsonl"), "a")
        step, seen, ce_acc, cnt_acc, t0 = 0, 0, [0.0] * a.depth, [0] * a.depth, time.time()
        h_acc, t_step = [0.0] * a.depth, time.time()
        model.train()
        for epoch in range(a.epochs):
            for w in iter_windows(a.data, a.window, stride, seed=a.seed + epoch, device=a.device):
                if not w["loss_mask"][1:].any():  # prompt-only window: no anchor counts
                    continue
                if w["topk_ids"].shape[1] != a.topk:
                    raise SystemExit(f"data has top-{w['topk_ids'].shape[1]}, --topk {a.topk}")
                with torch.autocast(torch.device(a.device).type, dtype=torch.bfloat16):
                    loss, counts, ce = window_loss(model, w, a.depth, weights, lookup)
                if not counts[0]:
                    continue
                (loss / a.tokens_per_step).backward()
                seen += counts[0]
                h = target_entropy(w, a.depth, lookup)
                for k in range(a.depth):
                    ce_acc[k] += ce[k]
                    h_acc[k] += h[k]
                    cnt_acc[k] += counts[k]
                if seen < a.tokens_per_step:
                    continue
                step += 1
                lr = a.lr * min(1.0, step / max(1, a.warmup))
                for g in opt.param_groups:
                    g["lr"] = lr
                gn = float(torch.nn.utils.clip_grad_norm_(params, a.clip))
                opt.step()
                opt.zero_grad(set_to_none=True)
                rec = {"step": step, "epoch": epoch, "lr": lr, "grad_norm": round(gn, 4), "anchors": cnt_acc,
                       "ce": [round(c / n, 5) if n else None for c, n in zip(ce_acc, cnt_acc)],
                       "kl": [round((c - e) / n, 5) if n else None for c, e, n in zip(ce_acc, h_acc, cnt_acc)],
                       "s": round(time.time() - t0, 1)}
                log.write(json.dumps(rec) + "\n")
                log.flush()
                now = time.time()
                mem = torch.cuda.max_memory_allocated() if torch.device(a.device).type == "cuda" else None
                last = list(step_samples(rec, labels, weights, a.epochs, cnt_acc[0] / max(now - t_step, 1e-9), mem))
                publish()
                seen, ce_acc, h_acc, cnt_acc, t_step = 0, [0.0] * a.depth, [0.0] * a.depth, [0] * a.depth, now
                if a.save_every and step % a.save_every == 0:  # ponytail: tensors only, no optimizer state (no resume)
                    export(model, names, os.path.join(a.out, f"ckpt-step{step:06d}.safetensors"), {**meta, "step": step})
                if a.max_steps and step >= a.max_steps:
                    break
            if a.max_steps and step >= a.max_steps:
                break
        opt.zero_grad(set_to_none=True)  # a partial accumulation at the end is dropped
        log.close()
        res["steps"] = step
    export(model, names, os.path.join(a.out, "mtp_refit.safetensors"), meta)
    if a.heldout and a.eval_windows:
        res["after"] = evaluate(model, a.heldout, **ev)
        publish()
    json.dump(res, open(os.path.join(a.out, "eval.json"), "w"), indent=1)
    return res


def main(argv=None):
    ap = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    ap.add_argument("--snapshot", required=True)
    ap.add_argument("--draft-vocab", help="draft vocab id list (default: full vocab)")
    ap.add_argument("--data", required=True)
    ap.add_argument("--heldout")
    ap.add_argument("--trainable", default="dense", choices=["dense", "dense-norouter"])
    ap.add_argument("--depth", type=int, default=6)
    ap.add_argument("--depth-weights", default="equal", help="equal | decay[:r] (r default 0.6)")
    ap.add_argument("--loss", default="kl", choices=["kl"], help="soft CE to the target top-k (= KL + const)")
    ap.add_argument("--topk", type=int, default=20, help="must match the capture's VLLM_MTP_CAPTURE_TOPK")
    ap.add_argument("--window", type=int, default=2048)
    ap.add_argument("--window-stride", type=int,
                    help="default window // 2: overlapping windows, each anchor trained once with >= window/2 keys")
    ap.add_argument("--lr", type=float, default=2e-5)
    ap.add_argument("--warmup", type=int, default=20)
    ap.add_argument("--clip", type=float, default=1.0)
    ap.add_argument("--epochs", type=int, default=2)
    ap.add_argument("--max-steps", type=int, default=0)
    ap.add_argument("--save-every", type=int, default=0,
                    help="every N optimizer steps, export the trainable tensors to <out>/ckpt-stepNNNNNN.safetensors")
    ap.add_argument("--tokens-per-step", type=int, default=8192, help="valid depth-0 anchors per optimizer step")
    ap.add_argument("--eval-windows", type=int, default=200, help="held-out windows per eval (0 = skip)")
    ap.add_argument("--device", default="cuda" if torch.cuda.is_available() else "cpu")
    ap.add_argument("--experts-impl", help="transformers experts implementation (default eager loop)")
    ap.add_argument("--kv-fp8", choices=["on", "off"], default="on",
                    help="fp8 round trip of the drafter K/V: on = served --kv-cache-dtype fp8, off = drafter KV in BF16")
    ap.add_argument("--seed", type=int, default=97)
    ap.add_argument("--out", required=True)
    ap.add_argument("--metrics-file", help="Prometheus textfile to rewrite per step (off by default)")
    a = ap.parse_args(argv)
    res = train(a)
    print(json.dumps({k: res[k] for k in ("steps",) if k in res}))


if __name__ == "__main__":
    main()
