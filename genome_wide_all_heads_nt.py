#!/usr/bin/env python3
"""
Collect GENOME-WIDE predictions for BOTH probe heads (linear probe + 3-layer NN)
in a single embedding pass — NTv2, for the fragment-vs-genome-wide transfer
analysis (best-head reported in the main table, full per-head in the appendix).

For each genome-wide CSV: extract the NT-v2 base-model embeddings ONCE, then apply
the saved linear probe AND 3-layer NN (from embedding_analysis_nt.py). Writes two
prediction CSVs per genome so the harvest can cluster each head:
    <output_dir>/lp/genome_wide_<stem>_predictions.csv   (+ _metrics.json)
    <output_dir>/nn/genome_wide_<stem>_predictions.csv   (+ _metrics.json)

FT genome-wide already exists from the standard pipeline; this fills in LP + NN.

Usage:
    python genome_wide_all_heads_nt.py \
        --model_path InstaDeepAI/nucleotide-transformer-v2-500m-multi-species \
        --embedding_dir <OUTPUT_DIR>/<w>/embedding/nt_500m \
        --input_dir <LAMBDA_BASE>/genome_wide/<w> \
        --output_dir <OUTPUT_DIR>/<w>/genome_wide_heads/nt_500m \
        --max_length 2048 --save_metrics
"""

import argparse
import glob
import json
import os
import pickle

import numpy as np
import pandas as pd
import torch
from transformers import AutoModelForMaskedLM, AutoTokenizer

from embedding_analysis_nt import ThreeLayerNN, extract_embeddings

LP_FILE = "linear_probe_pretrained.pkl"
NN_FILE = "three_layer_nn_pretrained.pt"
NN_SCALER_FILE = "three_layer_nn_pretrained_scaler.pkl"


def parse_args():
    p = argparse.ArgumentParser(description=__doc__,
                                formatter_class=argparse.RawDescriptionHelpFormatter)
    p.add_argument("--model_path", required=True)
    p.add_argument("--embedding_dir", required=True)
    p.add_argument("--input_dir", required=True)
    p.add_argument("--output_dir", required=True)
    p.add_argument("--pattern", default="*.csv")
    p.add_argument("--max_length", type=int, default=2048)
    p.add_argument("--batch_size", type=int, default=16)
    p.add_argument("--pooling", default="mean", choices=["mean", "cls", "last"])
    p.add_argument("--threshold", type=float, default=0.5)
    p.add_argument("--save_metrics", action="store_true")
    return p.parse_args()


def load_base_model(model_path, device):
    tokenizer = AutoTokenizer.from_pretrained(model_path, trust_remote_code=True)
    if tokenizer.pad_token is None:
        tokenizer.pad_token = tokenizer.eos_token
    full_model = AutoModelForMaskedLM.from_pretrained(model_path, trust_remote_code=True)
    if hasattr(full_model, "esm"):
        model = full_model.esm
    elif hasattr(full_model, "base_model"):
        model = full_model.base_model
    else:
        model = full_model
    return model.to(device).eval(), tokenizer


def load_heads(embedding_dir, device):
    with open(os.path.join(embedding_dir, LP_FILE), "rb") as f:
        bundle = pickle.load(f)
    lp = (bundle["classifier"], bundle["scaler"])
    ckpt = torch.load(os.path.join(embedding_dir, NN_FILE), map_location=device)
    nn_model = ThreeLayerNN(ckpt["input_dim"], ckpt["hidden_dim"]).to(device)
    nn_model.load_state_dict(ckpt["model_state_dict"]); nn_model.eval()
    with open(os.path.join(embedding_dir, NN_SCALER_FILE), "rb") as f:
        nn_scaler = pickle.load(f)
    return lp, (nn_model, nn_scaler)


def apply_lp(lp, emb):
    clf, scaler = lp
    return clf.predict_proba(scaler.transform(emb))


def apply_nn(nn, emb, device):
    model, scaler = nn
    X = torch.FloatTensor(scaler.transform(emb)).to(device)
    with torch.no_grad():
        return torch.softmax(model(X), dim=1).cpu().numpy()


def write_out(df, probs, threshold, out_csv, save_metrics):
    preds = (probs[:, 1] >= threshold).astype(int)
    out = df.copy()
    out["prob_0"] = probs[:, 0]; out["prob_1"] = probs[:, 1]; out["pred_label"] = preds
    os.makedirs(os.path.dirname(out_csv), exist_ok=True)
    out.to_csv(out_csv, index=False)
    if save_metrics and "label" in df.columns:
        from sklearn.metrics import matthews_corrcoef
        y = df["label"].astype(int).values
        m = {"mcc": float(matthews_corrcoef(y, preds)) if len(np.unique(y)) > 1 else 0.0}
        with open(out_csv.replace(".csv", "_metrics.json"), "w") as f:
            json.dump(m, f)


def main():
    args = parse_args()
    device = torch.device("cuda" if torch.cuda.is_available() else "cpu")
    print(f"device={device}  embedding_dir={args.embedding_dir}")
    model, tokenizer = load_base_model(args.model_path, device)
    lp, nn = load_heads(args.embedding_dir, device)

    csvs = sorted(glob.glob(os.path.join(args.input_dir, args.pattern)))
    print(f"{len(csvs)} genome CSV(s)")
    for i, csv in enumerate(csvs):
        df = pd.read_csv(csv)
        if "sequence" not in df.columns:
            print(f"  [skip] {os.path.basename(csv)} (no sequence)"); continue
        labels = df["label"].astype(int).tolist() if "label" in df.columns else [0] * len(df)
        emb, _ = extract_embeddings(model, tokenizer, df["sequence"].astype(str).tolist(),
                                    labels, args.batch_size, args.max_length, args.pooling, device)
        stem = os.path.basename(csv).replace(".csv", "")
        name = f"genome_wide_{stem}_predictions.csv" if not stem.startswith("genome_wide_") else f"{stem}_predictions.csv"
        write_out(df, apply_lp(lp, emb), args.threshold,
                  os.path.join(args.output_dir, "lp", name), args.save_metrics)
        write_out(df, apply_nn(nn, emb, device), args.threshold,
                  os.path.join(args.output_dir, "nn", name), args.save_metrics)
        if (i + 1) % 10 == 0:
            print(f"  {i+1}/{len(csvs)} done")
    print(f"Done -> {args.output_dir}/{{lp,nn}}/")


if __name__ == "__main__":
    main()
