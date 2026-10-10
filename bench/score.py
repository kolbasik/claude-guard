"""Score local injection classifiers on published datasets and on your own benign text.

  python score.py [--models DIR ...] [--laya english|multilingual ...] [--ollaya NAME ...] [--ollama NAME ...]
                  [--benign name=GLOB ... | --benign-file FILE ...] [--datasets ...]
  python score.py --export-benign FILE --benign name=GLOB ...   copy your benign text to another machine
  python score.py --combine [NAME ...] [--threshold 0.9] [--screen 0.5]

Every scored model leaves .cache/bench/scores/<name>.jsonl (label, source, score; no
text), so --combine can compare "any model", "2 of N", mean score and cascades without
scoring anything again.

Datasets (downloaded once into .cache/bench, never printed). A model trained on a
set scores well on it without detecting anything, so check a model's training data
and pick held-out sets:
  deepset     deepset/prompt-injections, test split: direct injections, labelled 0/1
  safeguard   xTRam1/safe-guard-prompt-injection, test split: direct, labelled 0/1
  nvidia      nvidia/Nemotron-RL-Agentic-Indirect-Prompt-Injection-v1: injections planted
              in record fields; the record's other fields are the benign side
--benign adds text from your own sources as benign-only, to measure false alarms on
your traffic: *.md is split into paragraphs, *.resx values are grouped like table rows.

Prints rates and latency only, never sample text.
"""
import argparse
import glob
import html
import itertools
import json
import os
import re
import statistics
import sys
import time
import urllib.parse
import urllib.request

sys.path.insert(0, os.path.join(os.path.dirname(os.path.abspath(__file__)), "..", "scripts"))
from decision import GUARD_QUESTIONS, Ollama, Ollaya  # noqa: E402

CACHE = os.path.join(os.path.dirname(os.path.abspath(__file__)), "..", ".cache", "bench")
ROWS_API = "https://datasets-server.huggingface.co/rows?dataset={}&config=default&split={}&offset={}&length=100"


def rows(dataset, split, limit):
    """Dataset rows via the Hugging Face datasets-server, cached as JSONL."""
    path = os.path.join(CACHE, f"{dataset.replace('/', '__')}.{split}.jsonl")
    if not os.path.exists(path):
        os.makedirs(CACHE, exist_ok=True)
        out, offset = [], 0
        while True:
            url = ROWS_API.format(urllib.parse.quote(dataset), split, offset)
            with urllib.request.urlopen(url, timeout=60) as r:
                page = [x["row"] for x in json.load(r)["rows"]]
            out += page
            offset += len(page)
            if len(page) < 100:
                break
        with open(path, "w", encoding="utf-8") as f:
            f.writelines(json.dumps(x) + "\n" for x in out)
    with open(path, encoding="utf-8") as f:
        return [json.loads(line) for line in f][:limit]


def _strings(o):
    if isinstance(o, dict):
        for v in o.values():
            yield from _strings(v)
    elif isinstance(o, list):
        for v in o:
            yield from _strings(v)
    elif isinstance(o, str):
        yield o


def deepset():
    """Test split only: its train split is in several models' training data."""
    return [(r["text"], r["label"], "deepset") for r in rows("deepset/prompt-injections", "test", 10_000)]


AIB_REVISION = "ef230359966c4d87b1c925aa56b8bf6e3f6ffed3"


def agentinjection():
    """AgentInjectionBench (ppradyoth, Apache-2.0): injections inside tool results, and benign controls
    written to look attack-adjacent. Each case is scored on what its tools returned, joined."""
    path = os.path.join(CACHE, "agentinjectionbench.jsonl")
    if not os.path.exists(path):
        os.makedirs(CACHE, exist_ok=True)
        url = f"https://huggingface.co/datasets/ppradyoth/AgentInjectionBench/resolve/{AIB_REVISION}/data/agent_injection_bench.jsonl"
        with urllib.request.urlopen(url, timeout=60) as r, open(path, "wb") as f:
            f.write(r.read())
    with open(path, encoding="utf-8") as f:
        cases = [json.loads(line) for line in f if line.strip()]
    return [("\n".join(str(m.get("content", "")) for m in c["conversation"] if m.get("role") == "tool_result"),
             int(c["ground_truth"] == "unsafe"), "aib") for c in cases]


def safeguard(limit=800):
    return [(r["text"], r["label"], "safeguard") for r in rows("xTRam1/safe-guard-prompt-injection", "test", limit)]


def nvidia(limit):
    """The field holding each planted injection as a positive, the record's other long fields as benign."""
    samples = []
    for r in rows("nvidia/Nemotron-RL-Agentic-Indirect-Prompt-Injection-v1", "train", limit):
        planted = ((r.get("injection") or {}).get("injection_text") or "").strip()
        env = r.get("environment")
        if isinstance(env, str):
            try:
                env = json.loads(env)
            except ValueError:
                env = {}
        fields = [s for s in _strings(env) if len(s) >= 60]
        holder = next((s for s in fields if planted[:60] in s), planted)
        samples.append((holder, 1, "nvidia"))
        samples += [(s, 0, "nvidia") for s in fields if planted[:60] not in s][:2]
    return samples


def benign(name, pattern, limit=60):
    """Benign-only samples from local files: markdown paragraphs, or resx values grouped in rows of 8."""
    texts = []
    for path in sorted(glob.glob(pattern, recursive=True)):
        if re.search(r"[\\/](?:bin|obj|node_modules)[\\/]|\.(?:en|sv)\.resx$", path):
            continue
        with open(path, encoding="utf-8", errors="replace") as f:
            data = f.read()
        if path.endswith(".resx"):
            values = [html.unescape(v).strip() for v in re.findall(r"<value>(.*?)</value>", data, re.S)]
            values = [v for v in values if len(v.split()) >= 3]
            texts += [" | ".join(values[i:i + 8]) for i in range(0, len(values), 8)]
        else:
            texts += [p.strip() for p in re.split(r"\n\s*\n", data) if 200 <= len(p.strip()) <= 1500]
        if len(texts) >= limit:
            break
    return [(t, 0, name) for t in texts[:limit]]


class Laya:
    """A laya checkpoint through its own package. Needs `pip install laya==0.3.21` (and so PyTorch)."""

    def __init__(self, checkpoint):
        import laya
        self.name = f"laya-{checkpoint}"
        self.checkpoint = checkpoint
        self.router = laya.Router()
        self.score("warm-up so the checkpoint load is not billed to the first sample")

    def score(self, text):
        answers = self.router.predict({"prompt": text}, GUARD_QUESTIONS, model=self.checkpoint)["answers"]
        return max(answers[q]["noul"] for q in GUARD_QUESTIONS)


SCORES = os.path.join(CACHE, "scores")


def rates(title, rows):
    """One line: share flagged among injected and among benign samples, per source. rows: (flagged, label, source)."""
    parts = {"caught": [], "false-alarm": []}
    for source in dict.fromkeys(s for _, _, s in rows):
        for label, kind in ((1, "caught"), (0, "false-alarm")):
            flags = [f for f, l, s in rows if s == source and l == label]
            if flags:
                parts[kind].append(f"{source} {100 * sum(flags) / len(flags):5.1f}%")
    print(f"  {title:<46} caught: {', '.join(parts['caught'])} | false alarms: {', '.join(parts['false-alarm'])}",
          flush=True)


def report(make, samples, mask=None):
    """Score samples (only where mask is true, if given) and save every score; skipped ones are null."""
    started = time.perf_counter()
    clf = make()
    load = time.perf_counter() - started
    scored, times = [], []
    for i, (text, label, source) in enumerate(samples):
        if mask and not mask[i]:
            scored.append((None, label, source))
            continue
        t = time.perf_counter()
        scored.append((clf.score(text), label, source))
        times.append(time.perf_counter() - t)
    os.makedirs(SCORES, exist_ok=True)
    with open(os.path.join(SCORES, f"{clf.name}.jsonl"), "w", encoding="utf-8") as f:
        f.writelines(json.dumps({"label": l, "source": s, "score": None if p is None else round(p, 5)}) + "\n"
                     for p, l, s in scored)
    print(f"\n{clf.name}: load {load:.1f} s, per sample p50 {1e3 * statistics.median(times):.0f} ms, "
          f"p95 {1e3 * sorted(times)[int(0.95 * len(times))]:.0f} ms", flush=True)
    if mask:
        print(f"  scored {len(times)} of {len(samples)} screened samples; usable only as a cascade's second model")
        return
    for th in (0.5, 0.9):
        rates(f"at {th}", [(p >= th, l, s) for p, l, s in scored])


def load_scores(name):
    with open(os.path.join(SCORES, f"{name}.jsonl"), encoding="utf-8") as f:
        return [json.loads(line) for line in f]


def combine(names, th, screen):
    """Rates for combinations of models already scored on the same samples; nothing is re-scored."""
    runs = {}
    for path in sorted(glob.glob(os.path.join(SCORES, "*.jsonl"))):
        name = os.path.basename(path)[:-len(".jsonl")]
        if not names or name in names:
            with open(path, encoding="utf-8") as f:
                runs[name] = [json.loads(line) for line in f]
    if len(runs) < 2:
        sys.exit(f"need at least two score files in {SCORES}, found {sorted(runs)}")
    base = next(iter(runs.values()))
    if any([(r["label"], r["source"]) for r in v] != [(r["label"], r["source"]) for r in base] for v in runs.values()):
        sys.exit("score files come from different sample sets; score every model with the same arguments")
    score = {n: [r["score"] for r in rows] for n, rows in runs.items()}
    n = len(base)
    # A partial run (--only-where) scored only screened samples, so it can only be a cascade's second model.
    full = [m for m in runs if None not in score[m]]

    def show(title, flags):
        rates(title, [(f, r["label"], r["source"]) for f, r in zip(flags, base)])

    print(f"\n{len(runs)} models ({len(runs) - len(full)} partial), {n} samples, flag at {th}; "
          f"a cascade screens at {screen}")
    for name in full:
        show(name, [p >= th for p in score[name]])
    if len(full) >= 2:
        show("any model", [any(score[m][i] >= th for m in full) for i in range(n)])
        show("mean score", [statistics.mean(score[m][i] for m in full) >= th for i in range(n)])
    if len(full) >= 3:
        show("at least 2 models", [sum(score[m][i] >= th for m in full) >= 2 for i in range(n)])
    # What server.py does with --confirm: a sure first model flags alone, an unsure one asks the second.
    for a, b in itertools.permutations(runs, 2):
        if a not in full:
            continue
        asked = [i for i in range(n) if th > score[a][i] >= screen]
        if any(score[b][i] is None for i in asked):
            print(f"  cascade {a} -> {b}: skipped, {b} was not scored on every sample {a} would ask about")
            continue
        show(f"cascade {a} -> {b}",
             [score[a][i] >= th or (score[a][i] >= screen and score[b][i] >= th) for i in range(n)])


def main():
    ap = argparse.ArgumentParser()
    ap.add_argument("--models", nargs="*", default=[], help="ONNX model directories")
    ap.add_argument("--laya", nargs="*", default=[], choices=["english", "multilingual"], help="laya checkpoints")
    ap.add_argument("--ollaya", nargs="*", default=[], help="Ollaya model names, e.g. decider:4b qwen3guard")
    ap.add_argument("--ollaya-url", default="http://127.0.0.1:11435")
    ap.add_argument("--ollama", nargs="*", default=[], help="Ollama decision model names, e.g. tev1:4b nimble")
    ap.add_argument("--ollama-url", default="http://127.0.0.1:11434")
    ap.add_argument("--benign", nargs="*", default=[], help="name=GLOB, benign-only local text")
    ap.add_argument("--export-benign", metavar="FILE", help="write the --benign samples to FILE and stop")
    ap.add_argument("--benign-file", nargs="*", default=[], help="benign samples written by --export-benign")
    ap.add_argument("--nvidia-rows", type=int, default=400)
    ap.add_argument("--datasets", nargs="+", default=["deepset", "safeguard"],
                    choices=["deepset", "safeguard", "nvidia", "aib"],
                    help="nvidia is in Horizon-Labs' training data, so it flatters that model")
    ap.add_argument("--scores", default="scores", help="folder under .cache/bench for score files; one per sample set")
    ap.add_argument("--combine", nargs="*", metavar="NAME",
                    help="compare combinations of already-scored models (all of them if no names)")
    ap.add_argument("--threshold", type=float, default=0.9, help="flag threshold for --combine")
    ap.add_argument("--screen", type=float, default=0.5, help="cascade screening threshold for --combine")
    ap.add_argument("--only-where", metavar="NAME",
                    help="score only samples NAME was unsure of (screen <= score < threshold): all a cascade "
                         "from NAME ever asks, so a slow second model costs a fraction of a full run")
    args = ap.parse_args()
    global SCORES
    SCORES = os.path.join(CACHE, args.scores)
    if args.combine is not None:
        return combine(args.combine, args.threshold, args.screen)
    local = [s for spec in args.benign for s in benign(*spec.split("=", 1))]
    if args.export_benign:
        with open(args.export_benign, "w", encoding="utf-8") as f:
            f.writelines(json.dumps({"text": t, "source": s}) + "\n" for t, _, s in local)
        print(f"{len(local)} benign samples written to {args.export_benign}")
        return
    for path in args.benign_file:
        with open(path, encoding="utf-8") as f:
            local += [(r["text"], 0, r["source"]) for r in map(json.loads, f)]
    loaders = {"deepset": deepset, "safeguard": safeguard, "nvidia": lambda: nvidia(args.nvidia_rows), "aib": agentinjection}
    samples = [s for name in args.datasets for s in loaders[name]()] + local
    print(f"{len(samples)} samples: {sum(l for _, l, _ in samples)} injected, "
          f"{sum(1 - l for _, l, _ in samples)} benign", flush=True)
    mask = None
    if args.only_where:
        rows = load_scores(args.only_where)
        if [(r["label"], r["source"]) for r in rows] != [(l, s) for _, l, s in samples]:
            sys.exit(f"{args.only_where} was scored on a different sample set; use the same dataset arguments")
        mask = [r["score"] is not None and args.screen <= r["score"] < args.threshold for r in rows]
        print(f"{sum(mask)} samples where {args.only_where} scored {args.screen}..{args.threshold}", flush=True)
    if args.models:
        from classifier import Classifier   # onnxruntime only when an ONNX model is scored
    for model in args.models:
        report(lambda m=model: Classifier(m), samples, mask)
    for checkpoint in args.laya:
        report(lambda c=checkpoint: Laya(c), samples, mask)
    for model in args.ollaya:
        report(lambda m=model: Ollaya(m, args.ollaya_url), samples, mask)
    for model in args.ollama:
        report(lambda m=model: Ollama(m, args.ollama_url), samples, mask)


if __name__ == "__main__":
    main()

