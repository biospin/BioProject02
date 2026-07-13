"""
BIOP02-90 — CPTAC 외부 예측을 slide_id 인덱스와 함께 저장 (cost-of-substitution 라우팅용).

각 receptor 엔드포인트(ER/PR/HER2) CLAM-SB 모델을 CPTAC 전체 슬라이드에 재추론.
예측은 라벨과 무관하므로 has_* 플래그로 거르지 않고 전 슬라이드(653) 예측을 제공한다
(측정 라벨 join·검증은 kkkim compute_cost 쪽에서 수행).

출력: experiments/sjpark/cptac_ext_predictions_indexed.csv
컬럼: slide_id, case_id, er_pred_prob, pr_pred_prob, her2_pred_prob
"""
import csv
from pathlib import Path
import numpy as np
import torch
import yaml
import sys
sys.path.insert(0, "/workspace/agents")
from modeling.baselines.attention_mil import CLAMSB

BASE = Path("/workspace/agents/modeling/experiments/sjpark")
MANI = "/workspace/data/cache/biop02/embedding_manifest_cptac_uni.csv"
SPLIT = "cptac_external"
ENDPOINTS = {
    "er":   ("er_status_clam_uni_v2",   "baseline_er_status_clam.yaml"),
    "pr":   ("pr_status_clam_uni_v2",   "baseline_pr_status_clam.yaml"),
    "her2": ("her2_status_clam_uni_v2", "baseline_her2_status_clam.yaml"),
}
CFG_DIR = Path("/workspace/agents/modeling/configs")

device = "cuda" if torch.cuda.is_available() else "cpu"


def load_model(exp_dir, cfg_name):
    cfg = yaml.safe_load(open(CFG_DIR / cfg_name))
    m = CLAMSB(feature_dim=cfg["embedding_dim"], hidden_dim=cfg["model"]["hidden_dim"],
               att_dim=cfg["model"]["att_dim"], dropout=cfg["model"]["dropout"]).to(device)
    m.load_state_dict(torch.load(BASE / exp_dir / "model.pt", map_location=device))
    m.eval()
    return m


rows = [r for r in csv.DictReader(open(MANI)) if r.get("split", "").strip() == SPLIT]
print(f"CPTAC external slides: {len(rows)}")

models = {ep: load_model(*v) for ep, v in ENDPOINTS.items()}

out = []
with torch.no_grad():
    for r in rows:
        emb = torch.tensor(np.load(r["embedding_path"])).to(device)
        probs = {}
        for ep, m in models.items():
            logit, _ = m(emb)
            probs[ep] = round(float(torch.sigmoid(logit).item()), 6)
        out.append({
            "slide_id": r["slide_id"],
            "case_id": r["case_id"],
            "er_pred_prob": probs["er"],
            "pr_pred_prob": probs["pr"],
            "her2_pred_prob": probs["her2"],
        })

out_path = BASE / "cptac_ext_predictions_indexed.csv"
with open(out_path, "w", newline="") as f:
    w = csv.DictWriter(f, fieldnames=["slide_id", "case_id", "er_pred_prob", "pr_pred_prob", "her2_pred_prob"])
    w.writeheader()
    w.writerows(out)
print(f"Saved: {out_path}  ({len(out)} rows)")
print("head:")
for r in out[:3]:
    print(" ", r)
