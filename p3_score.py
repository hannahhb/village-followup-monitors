"""Score every Phase 3 method on out/p3_set.jsonl, leaving out the first 10 rows (used to tune the prompt). Free."""
import json, random, collections
from common import OUT
from p3_free import KEYWORDS, auroc, catch_at

rows = [json.loads(l) for l in open(OUT / "p3_set.jsonl")]
tuned = {r["pid"] for r in rows[:10]}
test = [r for r in rows if r["pid"] not in tuned]
labels = {r["pid"]: r["label"] == "planted" for r in test}
scores = collections.defaultdict(dict)
for l in open(OUT / "p3_scores.jsonl"):
    s = json.loads(l)
    if s["pid"] in labels and s["p_false"] is not None:
        scores[(s["model"].split("/")[-1], s["method"])][s["pid"]] = float(s["p_false"])
random.seed(0)
methods = {("baseline", "random"): {p: random.random() for p in labels},
           ("baseline", "keyword"): {r["pid"]: len(KEYWORDS.findall(r["message"])) for r in test}}
methods.update(scores)
n_true = sum(not v for v in labels.values())
print(f"test rows: {len(test)} ({len(test) - n_true} planted, {n_true} true); 5% false alarms = {int(.05 * n_true)} true claims flagged")
for (model, method), sc in methods.items():
    pids = [p for p in labels if p in sc]
    lab, val = [labels[p] for p in pids], [sc[p] for p in pids]
    hi_c = sum(v >= 50 for l, v in zip(lab, val) if l) / sum(lab)
    hi_f = sum(v >= 50 for l, v in zip(lab, val) if not l) / (len(lab) - sum(lab))
    print(f"{model:12s} {method:8s} n={len(pids):3d}  AUROC {auroc(lab, val):.2f}  caught at 5% FA {catch_at(lab, val, .05):.0%}  "
          f"| score>=50: caught {hi_c:.0%}, false alarms {hi_f:.0%}")
