"""RLHF 2-qadam: reward model o'qitish -> rlhf/models/reward/.

Kaggle'da (GPU):  python rlhf/train_reward.py
CPU'da sinov:     python rlhf/train_reward.py --max-steps 2

Reward model javobga bitta son (ball) beradi va PPO'da odam o'rnini bosadi: har bir yangi javobni baholaydi.
U DPO v2 bilan bir xil juftliklarda (dpo/data_v2) o'qitiladi, shunda RLHF va DPO bir xil data'da solishtiriladi.
  Loss (Bradley-Terry): -log sigmoid(r(chosen) - r(rejected)) — chosen balli rejected'nikidan katta bo'lsin.
  DPO loss'i ham aynan shu formula, faqat u yerda r = beta * log(policy / reference): alohida reward model yo'q.
"""
import argparse
import json
import math
import random
import time
from pathlib import Path

import torch
import torch.nn.functional as F
from transformers import AutoTokenizer

import scalar_model

HERE = Path(__file__).parent
ROOT = HERE.parent
MAX_TOKENS = 384   # bundan uzun namuna qirqiladi


def encode(tok, prompt, answer):
    """SFT va DPO'dagi bilan bir xil format: prompt chat template'da, javob oxirida <|endoftext|>."""
    text = tok.apply_chat_template([{"role": "user", "content": prompt}], tokenize=False, add_generation_prompt=True)
    return (tok(text)["input_ids"] + tok(answer)["input_ids"] + [tok.eos_token_id])[:MAX_TOKENS]


def load_pairs(tok, folder, name):
    rows = [json.loads(line) for line in (folder / name).read_text(encoding="utf-8").splitlines()]
    return [{**r, "c": encode(tok, r["prompt"], r["chosen"]), "r": encode(tok, r["prompt"], r["rejected"])} for r in rows]


def pair_scores(model, batch, pad_id, device):
    s = scalar_model.last_scores(model, [p["c"] for p in batch] + [p["r"] for p in batch], pad_id, device)
    return s[:len(batch)], s[len(batch):]


@torch.no_grad()
def evaluate(model, data, batch_size, pad_id, device):
    model.eval()
    sc, sr = zip(*(pair_scores(model, data[i:i + batch_size], pad_id, device) for i in range(0, len(data), batch_size)))
    sc, sr = torch.cat(sc), torch.cat(sr)
    model.train()
    return {"loss": -F.logsigmoid(sc - sr).mean().item(), "acc": (sc > sr).float().mean().item()}, sc, sr


def length_report(data, sc, sr):
    """Reward model qisqa javobni yaxshi deb o'rganib olmadimi? (DPO v1'dagi length bias)."""
    shorter = [(c > r) == (len(p["chosen"]) < len(p["rejected"]))
               for p, c, r in zip(data, sc.tolist(), sr.tolist()) if len(p["chosen"]) != len(p["rejected"])]
    scores = sc.tolist() + sr.tolist()
    lengths = [len(p["chosen"]) for p in data] + [len(p["rejected"]) for p in data]
    corr = torch.corrcoef(torch.tensor([scores, lengths], dtype=torch.float))[0, 1].item()
    return sum(shorter) / max(1, len(shorter)), corr


def length_gate(data, sc, sr):
    """PPO'dan oldingi tekshiruv, rad etishsiz vazifalarda (u yerda to'g'ri javob tabiatan qisqa).
    Reward model qisqa javobni data'dagidan ancha ko'p tanlasa yoki ball uzunlik bilan kuchli bog'liq bo'lsa,
    PPO uni ishlatmaydi (train_ppo.py, --force bilan o'tkazib yuborish mumkin). RLHF v1 aynan shu sababli yutqazgan."""
    keep = [i for i, p in enumerate(data) if p["task"] not in ("harmful", "cheating", "unknown")]
    if len(keep) < 2:
        return {"ok": True}
    part = [data[i] for i in keep]
    shorter, _ = length_report(part, sc[keep], sr[keep])
    unequal = [p for p in part if len(p["chosen"]) != len(p["rejected"])]
    in_data = sum(len(p["chosen"]) < len(p["rejected"]) for p in unequal) / max(1, len(unequal))
    # Korrelyatsiya juftlik ichida: ball farqi va uzunlik farqi. Har xil promptlar ballarini aralashtirib bo'lmaydi:
    # reward model har vazifaga har xil o'rtacha ball beradi (v1: ro'yxat ~23.5, "Bilmayman" ~28) va vazifalarning
    # javob uzunligi ham har xil — mukammal hakamda ham shunday korrelyatsiya -0.22 chiqadi, uzunlikka hech aloqasi yo'q.
    diff = (sc[keep] - sr[keep]).float().cpu()   # ballar GPU'da, uzunliklar CPU'da: bir joyga
    dlen = torch.tensor([len(p["chosen"]) - len(p["rejected"]) for p in part], dtype=torch.float)
    corr = torch.corrcoef(torch.stack([diff, dlen]))[0, 1].item() if dlen.std() > 0 else 0.0
    return {"rm_picks_shorter": round(shorter, 3), "data_chosen_shorter": round(in_data, 3),
            "pair_corr": round(corr, 3), "ok": shorter <= in_data + 0.15 and corr >= -0.3}


def main():
    p = argparse.ArgumentParser()
    p.add_argument("--base", default="Qwen2.5-0.5B", help="reward model uchun base (policy bilan bir xil tokenizer)")
    p.add_argument("--sft-adapter", help="reward modelni SFT model'dan boshlash (ixtiyoriy, masalan sft-lora-v3 1.5B uchun)")
    p.add_argument("--data", default="dpo/data_v2", help="chosen/rejected juftliklari (DPO v2 bilan bir xil)")
    p.add_argument("--out", default="reward", help="rlhf/models/ ichidagi natija papkasi")
    p.add_argument("--epochs", type=int, default=2)
    p.add_argument("--batch-size", type=int, default=8, help="juftliklar soni (ketma-ketliklar 2 barobar)")
    p.add_argument("--lr", type=float, default=5e-5)
    p.add_argument("--rank", type=int, default=16)
    p.add_argument("--max-steps", type=int)
    args = p.parse_args()

    random.seed(42)
    torch.manual_seed(42)
    device = "cuda" if torch.cuda.is_available() else "cpu"
    tok = AutoTokenizer.from_pretrained(ROOT / args.base)
    tok.pad_token = tok.pad_token or tok.eos_token
    pad = tok.pad_token_id

    train = load_pairs(tok, ROOT / args.data, "train.jsonl")
    val = load_pairs(tok, ROOT / args.data, "val.jsonl")
    if args.max_steps:
        train, val = train[:args.max_steps * args.batch_size], val[:args.batch_size]

    model = scalar_model.build(args.base, args.sft_adapter, args.rank, device).train()
    model.backbone.print_trainable_parameters()
    params = [q for q in model.parameters() if q.requires_grad]
    optimizer = torch.optim.AdamW(params, lr=args.lr, weight_decay=0.0)
    total_steps = args.max_steps or math.ceil(len(train) / args.batch_size) * args.epochs
    warmup = max(1, total_steps // 10)
    scheduler = torch.optim.lr_scheduler.LambdaLR(
        optimizer, lambda s: (s + 1) / warmup if s < warmup else max(0.0, (total_steps - s) / max(1, total_steps - warmup)))

    s0, _, _ = evaluate(model, val, args.batch_size, pad, device)
    print(f"Boshlanishida: val loss {s0['loss']:.3f} (tasodifiy head: ~0.693), val acc {s0['acc']:.2f}", flush=True)
    out = HERE / "models" / args.out
    log, step, start, best = [{"step": 0, "val": s0}], 0, time.time(), float("inf")
    for epoch in range(1, args.epochs + 1):
        random.shuffle(train)
        for i in range(0, len(train), args.batch_size):
            sc, sr = pair_scores(model, train[i:i + args.batch_size], pad, device)
            loss = -F.logsigmoid(sc - sr).mean()
            loss.backward()
            torch.nn.utils.clip_grad_norm_(params, 1.0)
            optimizer.step()
            scheduler.step()
            optimizer.zero_grad()
            step += 1
            acc = (sc > sr).float().mean().item()
            log.append({"step": step, "epoch": epoch, "loss": round(loss.item(), 4), "acc": round(acc, 4)})
            if step <= 3 or step % 10 == 0 or step == total_steps:
                elapsed = time.time() - start
                print(f"qadam {step}/{total_steps} | loss {loss.item():.3f} | acc {acc:.2f} | "
                      f"farq {(sc - sr).mean().item():+.2f} | qoldi ~{elapsed / step * (total_steps - step) / 60:.0f} daq",
                      flush=True)
            if step == total_steps:
                break
        sv, _, _ = evaluate(model, val, args.batch_size, pad, device)
        log.append({"step": step, "epoch": epoch, "val": sv})
        saved = sv["loss"] < best
        if saved:
            best = sv["loss"]
            # Ballar normallashtiriladi: PPO'da reward o'rtachasi 0, og'ishi 1 bo'lsin. Statistika train javoblaridan.
            _, tc, tr = evaluate(model, train, args.batch_size, pad, device)
            both = torch.cat([tc, tr])
            scalar_model.save(model, out, {"base": args.base, "sft_adapter": args.sft_adapter,
                                           "mean": both.mean().item(), "std": both.std().item() if len(both) > 1 else 1.0,
                                           "val_acc": sv["acc"], "val_loss": sv["loss"], "epoch": epoch})
        print(f"=== epoch {epoch} | val loss {sv['loss']:.3f} | val acc {sv['acc']:.2f}" + (" | saqlandi" if saved else ""),
              flush=True)
        if step == total_steps:
            break

    # Saqlangan (eng yaxshi) model bilan yakuniy tekshiruv.
    model, meta = scalar_model.load(out, device)
    for name, data in (("train", train), ("val", val)):
        s, sc, sr = evaluate(model, data, args.batch_size, pad, device)
        shorter, corr = length_report(data, sc, sr)
        print(f"{name}: acc {s['acc']:.2f} | qisqa javobni afzal ko'rdi: {shorter:.0%} juftlikda | "
              f"ball va uzunlik korrelyatsiyasi {corr:+.2f}")
    print("Data'da chosen qisqaroq:", f"{sum(len(p['chosen']) < len(p['rejected']) for p in train) / len(train):.0%}",
          "(reward model shundan ko'p bo'lsa, uzunlikni o'rgangan)")
    right = (sc > sr).tolist()   # sc, sr: oxirgi sikldagi val
    for task in sorted({p["task"] for p in val}):
        mine = [ok for p, ok in zip(val, right) if p["task"] == task]
        print(f"  val acc [{task}]: {sum(mine) / len(mine):.2f} ({len(mine)} juftlik)")
    meta["length_gate"] = length_gate(val, sc, sr)
    print("Uzunlik tekshiruvi (val, rad etishsiz):", meta["length_gate"],
          "" if meta["length_gate"]["ok"] else "-> O'TMADI: PPO bu reward modelni ishlatmaydi")
    (out / "meta.json").write_text(json.dumps(meta, indent=1), encoding="utf-8")
    (out / "training_log.json").write_text(json.dumps(log, indent=1), encoding="utf-8")
    print(f"Tayyor: {out} | eng yaxshi val loss {best:.3f} | ball o'rtachasi {meta['mean']:+.2f}, og'ishi {meta['std']:.2f} | "
          f"jami {(time.time() - start) / 60:.1f} daqiqa")


if __name__ == "__main__":
    main()
