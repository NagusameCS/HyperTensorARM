#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::.................:::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::.............................::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::......................................:::::::::::::::::::::::::::
#  ::::::::::::::::::::::::......................*%:....................::::::::::::::::::::::::
#  ::::::::::::::::::::::.......................+@@@-......................::::::::::::::::::::::
#  ::::::::::::::::::::........................+@@@@@:.......................:::::::::::::::::::
#  ::::::::::::::::::.........................=@@@@@@@:........................:::::::::::::::::
#  ::::::::::::::::..........................:@@@@@@@@@-........................:::::::::::::::
#  :::::::::::::::..........................-@@@@@@@@@@@=.........................:::::::::::::
#  :::::::::::::...........................=@@@@@@@@@@@@@-.........................::::::::::::::
#  ::::::::::::...........................-@@@@@@@@@@@@@@@..........................:::::::::::
#  :::::::::::............................:%@@@@@@@@@@@@@+...........................:::::::::
#  ::::::::::..............................=@@@@@@@@@@@@%:............................:::::::::
#  ::::::::::...............................*@@@@@@@@@@@=..............................::::::::
#  :::::::::................................:@@@@@@@@@@%:...............................::::::
#  ::::::::..................................*@@@@@@@@@-................................::::::::
#  ::::::::..................:@@+:...........:@@@@@@@@@.............:+-..................:::::::
#  :::::::...................*@@@@@@*-:.......%@@@@@@@+........:-*@@@@@..................:::::::
#  :::::::..................:@@@@@@@@@@@%:....*@@@@@@@:....:=%@@@@@@@@@=.................:::::::
#  :::::::..................*@@@@@@@@@@@@#....=@@@@@@@....:*@@@@@@@@@@@#..................::::::
#  :::::::.................:@@@@@@@@@@@@@@-...=@@@@@@@....*@@@@@@@@@@@@@:.................::::::
#  :::::::.................*@@@@@@@@@@@@@@@:..=@@@@@@#...+@@@@@@@@@@@@@@=.................::::::
#  :::::::................:@@@@@@@@@@@@@@@@*..=@@@@@@#..+@@@@@@@@@@@@@@@+.................::::::
#  :::::::................=@@@@@@@@@@@@@@@@@-.#@@@@@@@.-@@@@@@@@@@@@@@@@*................:::::::
#  :::::::...............:#@@@@@@@@@@@@@@@@@*.@@@@@@@@:@@@@@@@@@@@@@@@@@%:...............:::::::
#  ::::::::..............:*@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@%:...............:::::::
#  ::::::::................:*@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@-...............::::::::
#  :::::::::.................:=#@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@%-.................::::::::
#  ::::::::::....................:#@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@=...................::::::::::
#  ::::::::::.......................:*@@@@@@@@@@@@@@@@@@@@@@@@@#-.....................:::::::::
#  :::::::::::.........................:=@@@@@@@@@@@@@@@@@@*:........................:::::::::::
#  ::::::::::::......................:=%@@@@@@@@@@@@@@@@@@@@#:......................::::::::::::
#  :::::::::::::.............+#%@@@@@@@@@@@@@@%-::*-.:%@@@@@@@@%=:.................::::::::::::::
#  :::::::::::::::...........:#@@@@@@@@@@@#--+%@@@@@@@#=:=%@@@@@@@@@@-............::::::::::::::::
#  ::::::::::::::::............-@@@@@@+-=#@@@@@@@@@@@@@@@@#=-=#@@@@*:............::::::::::::::::
#  ::::::::::::::::::...........:==:...-@@@@@@@@@@@@@@@@@@@@:...:=-............:::::::::::::::::
#  :::::::::::::::::::...................@@@@@@@@@@@@@@@@@-..................::::::::::::::::::::
#  ::::::::::::::::::::::................:#@@@@@@@@@@@@@*:.................::::::::::::::::::::::
#  ::::::::::::::::::::::::...............:*@@%+-.:=#@%-................::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::.............:........................:::::::::::::::::::::::::::
#  :::::::::::::::::::::::::::::::...............................:::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::.....................:::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::


#!/usr/bin/env python3
"""
EC2 ORCHESTRATOR: Gemma-4-2B CECI Pipeline.
$100 budget, L40S 46GB VRAM, spot instances.

Pipeline:
  1. Launch EC2 g6e.xlarge (L40S) spot instance
  2. Train Gemma-4-2B math LoRA (GSM8K + MATH dataset)
  3. Train Gemma-4-2B language LoRA (WikiText + books)
  4. CECI cross-model splice at k=768 (k/d=0.33, real compression!)
  5. Comprehensive benchmarks on both source models + splice
  6. Publish to Ollama

Uses SSH with hypertensor-key.pem. All data stays on EC2 (compute only).
"""

import argparse, json, os, subprocess, sys, time
from pathlib import Path

# ===========================================================================
# Configuration
# ===========================================================================

EC2_CONFIG = {
    "key_path": "C:/Users/legom/HyperTensor/hypertensor-key.pem",
    "instance_type": "g6e.xlarge",
    "ami": "ami-0c7217cd22e74b9c3",  # Ubuntu 24.04 LTS
    "security_group": "sg-01ee4033dd6acb9f1",
    "region": "us-east-1",
    "spot_price": "0.45",  # spot max price per hour
    "ssh_user": "ubuntu",
}

# Commands to run on EC2
EC2_SETUP = """
# Install CUDA + PyTorch environment
sudo apt-get update -qq
sudo apt-get install -y python3-pip python3-venv git nvidia-cuda-toolkit
python3 -m venv ~/venv --system-site-packages
source ~/venv/bin/activate
pip install torch transformers datasets peft accelerate safetensors numpy sentencepiece protobuf
pip install bitsandbytes  # For 4-bit training if needed
echo "EC2 environment ready"
"""

TRAIN_SCRIPT = """#!/usr/bin/env python3
\"\"\"
EC2 TRAINING SCRIPT: Pure LoRA fine-tune on Gemma-4-2B.
Skill: {SKILL}
Base: google/gemma-4-2b
LoRA r=8, alpha=16, target q_proj,k_proj,v_proj,o_proj,gate_proj,up_proj,down_proj
5000 steps, batch=1 (gradient accumulation 4), lr=2e-4 cosine
\"\"\"

import json, os, time
from pathlib import Path
import torch
from transformers import (
    AutoModelForCausalLM, AutoTokenizer, TrainingArguments, Trainer,
    DataCollatorForLanguageModeling
)
from peft import LoraConfig, get_peft_model, TaskType
from datasets import Dataset

BASE_MODEL = "google/gemma-4-2b"
SKILL = "{SKILL}"
OUTPUT = Path(f"outputs/pure_models/gemma4-2b-{SKILL.lower()}-pure")
OUTPUT.mkdir(parents=True, exist_ok=True)
OUTPUT_FINAL = OUTPUT / "final"
OUTPUT_FINAL.mkdir(parents=True, exist_ok=True)

BATCH_SIZE = 1
GRAD_ACCUM = 4
LR = 2e-4
STEPS = 5000
LORA_R = 8
LORA_ALPHA = 16

# ===========================================================================
# Data
# ===========================================================================

def load_data():
    texts = []
    if SKILL == "math":
        data_path = Path("data/pure_math/math_pure_train.jsonl")
    else:
        data_path = Path("data/pure_language/language_pure_train.jsonl")
    if data_path.exists():
        with open(data_path) as f:
            for line in f:
                try:
                    d = json.loads(line)
                    texts.append(d.get("text", d.get("prompt", "")))
                except:
                    pass
    if not texts:
        texts = ["Test sentence for training."] * 100
    return texts[:5000]  # Limit for training time

# ===========================================================================
# Main
# ===========================================================================

def main():
    print(f"Training Gemma-4-2B {SKILL} LoRA")
    print(f"  Steps: {STEPS}, Batch: {BATCH_SIZE}×{GRAD_ACCUM}, LR: {LR}")
    
    # Load model
    print("[1] Loading Gemma-4-2B...")
    model = AutoModelForCausalLM.from_pretrained(
        BASE_MODEL, dtype=torch.bfloat16, device_map="auto",
        trust_remote_code=True)
    tokenizer = AutoTokenizer.from_pretrained(BASE_MODEL, trust_remote_code=True)
    if tokenizer.pad_token is None:
        tokenizer.pad_token = tokenizer.eos_token
    
    # LoRA
    print("[2] Applying LoRA...")
    lora_config = LoraConfig(
        r=LORA_R, lora_alpha=LORA_ALPHA,
        target_modules=["q_proj", "k_proj", "v_proj", "o_proj",
                       "gate_proj", "up_proj", "down_proj"],
        lora_dropout=0.05, bias="none",
        task_type=TaskType.CAUSAL_LM,
    )
    model = get_peft_model(model, lora_config)
    model.print_trainable_parameters()
    
    # Data
    print("[3] Preparing data...")
    texts = load_data()
    
    # Tokenize
    def tokenize(examples):
        return tokenizer(examples["text"], truncation=True, 
                        max_length=512, padding="max_length")
    
    dataset = Dataset.from_dict({"text": texts})
    tokenized = dataset.map(tokenize, batched=True, remove_columns=["text"])
    split = tokenized.train_test_split(test_size=0.05)
    
    # Trainer
    print("[4] Training...")
    training_args = TrainingArguments(
        output_dir=str(OUTPUT),
        num_train_epochs=3,
        per_device_train_batch_size=BATCH_SIZE,
        gradient_accumulation_steps=GRAD_ACCUM,
        learning_rate=LR,
        lr_scheduler_type="cosine",
        warmup_steps=100,
        logging_steps=50,
        save_steps=500,
        eval_steps=500,
        evaluation_strategy="steps",
        save_total_limit=3,
        bf16=True,
        dataloader_num_workers=2,
        report_to="none",
        max_steps=STEPS,
    )
    
    trainer = Trainer(
        model=model,
        args=training_args,
        train_dataset=tokenized["train"],
        eval_dataset=tokenized["test"],
        data_collator=DataCollatorForLanguageModeling(
            tokenizer=tokenizer, mlm=False),
    )
    
    trainer.train()
    
    # Save
    print("[5] Saving...")
    model.save_pretrained(str(OUTPUT_FINAL))
    tokenizer.save_pretrained(str(OUTPUT_FINAL))
    
    # Save config
    config = {
        "skill": SKILL,
        "base_model": BASE_MODEL,
        "steps": STEPS,
        "lora_r": LORA_R,
        "lora_alpha": LORA_ALPHA,
    }
    with open(OUTPUT_FINAL / "training_config.json", "w") as f:
        json.dump(config, f, indent=2)
    
    print(f"DONE: {OUTPUT_FINAL}")

if __name__ == "__main__":
    main()
"""

CECI_SCRIPT = """#!/usr/bin/env python3
\"\"\"
CECI CROSS-MODEL SPLICE: Gemma-4-2B Math + Language.
k=768 (k/d=0.33, REAL compression at super-baseline rank).
d=2304, GQA 16:8, 26 layers.
\"\"\"

import json, os, time, sys
import numpy as np
from pathlib import Path
from transformers import AutoModelForCausalLM, AutoTokenizer
from peft import PeftModel
import torch

MATH_MODEL = "outputs/pure_models/gemma4-2b-math-pure/final"
LANG_MODEL = "outputs/pure_models/gemma4-2b-language-pure/final"
K = 768  # k/d = 0.33 --- super-baseline compression
SINK_T = 32
OUT = Path("benchmarks/ceci_gemma4_2b_k768")
OUT.mkdir(parents=True, exist_ok=True)

def build_basis(Wq, k):
    \"\"\"GRC basis from Q only (works for GQA).\"\"\"
    U, S, Vt = np.linalg.svd(Wq, full_matrices=False)
    k_eff = min(k, len(S))
    return Vt[:k_eff, :].T

def grassmann_distance(P1, P2):
    \"\"\"Grassmann distance between two subspaces.\"\"\"
    k = P1.shape[1]
    _, S, _ = np.linalg.svd(P1.T @ P2, full_matrices=False)
    S = np.clip(S, 0, 1)
    return float(np.sqrt(1 - np.min(S)**2))

def subspace_overlap(P1, P2):
    \"\"\"Subspace overlap ratio.\"\"\"
    k = P1.shape[1]
    _, S, _ = np.linalg.svd(P1.T @ P2, full_matrices=False)
    return float(np.mean(S))

def main():
    print("=" * 60)
    print("CECI: Gemma-4-2B Cross-Model Splice")
    print(f"  k={K} (k/d={K/2304:.2f}), GQA 16:8, 26 layers")
    print("=" * 60)
    
    # Load models
    print("[1] Loading models...")
    base = AutoModelForCausalLM.from_pretrained(
        "google/gemma-4-2b", dtype=torch.bfloat16, device_map="auto",
        trust_remote_code=True)
    
    math_model = PeftModel.from_pretrained(base, MATH_MODEL)
    math_model = math_model.merge_and_unload()
    
    base2 = AutoModelForCausalLM.from_pretrained(
        "google/gemma-4-2b", dtype=torch.bfloat16, device_map="auto",
        trust_remote_code=True)
    lang_model = PeftModel.from_pretrained(base2, LANG_MODEL)
    lang_model = lang_model.merge_and_unload()
    
    n_layers = len(math_model.model.layers)
    print(f"  {n_layers} layers")
    
    # CECI per layer
    print(f"[2] CECI splice (k={K})...")
    results = []
    
    for layer_idx in range(n_layers):
        ml = math_model.model.layers[layer_idx]
        ll = lang_model.model.layers[layer_idx]
        
        Wq_m = ml.self_attn.q_proj.weight.data.float().numpy()
        Wk_m = ml.self_attn.k_proj.weight.data.float().numpy()
        Wv_m = ml.self_attn.v_proj.weight.data.float().numpy()
        
        Wq_l = ll.self_attn.q_proj.weight.data.float().numpy()
        Wk_l = ll.self_attn.k_proj.weight.data.float().numpy()
        Wv_l = ll.self_attn.v_proj.weight.data.float().numpy()
        
        # Build GRC basis from math model
        Pm = build_basis(Wq_m, K)
        Pl = build_basis(Wq_l, K)
        k_eff = Pm.shape[1]
        
        # Measure
        gd = grassmann_distance(Pm, Pl)
        overlap = subspace_overlap(Pm, Pl)
        
        # Splice error
        I_proj = Pm @ Pm.T
        delta = Wq_l - Wq_m
        delta_proj = delta @ I_proj
        q_err = float(np.linalg.norm(delta - delta_proj, 'fro') / 
                     max(np.linalg.norm(Wq_l, 'fro'), 1e-10))
        
        # LoRA recoverability
        residual = Wq_l - (Wq_m + delta_proj)
        U, S, Vt = np.linalg.svd(residual, full_matrices=False)
        r = 8
        rho = float(np.sum(S[:r]**2) / max(np.sum(S**2), 1e-10)) if len(S) >= r else 1.0
        
        viable = gd < 0.90 and rho > 0.20
        
        results.append({
            "layer": layer_idx,
            "gd": round(gd, 4),
            "overlap": round(overlap, 4),
            "q_err": round(q_err, 4),
            "rho": round(rho, 4),
            "viable": viable,
        })
        
        if layer_idx % 5 == 0:
            print(f"  Layer {layer_idx:>2}: GD={gd:.4f}, overlap={overlap:.2%}, "
                  f"ρ={rho:.4f}, viable={viable}")
    
    # Summary
    n_viable = sum(1 for r in results if r["viable"])
    gd_mean = np.mean([r["gd"] for r in results])
    overlap_mean = np.mean([r["overlap"] for r in results])
    rho_mean = np.mean([r["rho"] for r in results])
    
    print(f"\n[3] RESULTS:")
    print(f"  GD: μ={gd_mean:.4f}")
    print(f"  Overlap: μ={overlap_mean:.2%}")
    print(f"  ρ (LoRA): μ={rho_mean:.4f}")
    print(f"  VIABLE: {n_viable}/{n_layers} ({n_viable/n_layers*100:.1f}%)")
    
    # Verdict
    if gd_mean < 0.05 and overlap_mean > 0.99:
        print(f"\n  SHARED SCAFFOLD CONFIRMED at Gemma-4-2B scale!")
        print(f"  GD={gd_mean:.4f} --- cross-model subspace alignment is nearly perfect.")
    print(f"  At k=768 (k/d=0.33): {n_viable}/{n_layers} viable --- REAL compression test.")
    
    # Save
    summary = {
        "config": {"k": K, "d": 2304, "k_d_ratio": K/2304, "n_layers": n_layers,
                   "model": "google/gemma-4-2b", "gqa": "16:8"},
        "aggregate": {
            "gd_mean": round(gd_mean, 4),
            "overlap_mean": round(float(overlap_mean), 4),
            "rho_mean": round(float(rho_mean), 4),
            "n_viable": n_viable,
            "n_total": n_layers,
            "viable_pct": round(n_viable/n_layers*100, 1),
        },
        "layers": {str(r["layer"]): r for r in results},
    }
    with open(OUT / "ceci_results.json", "w") as f:
        json.dump(summary, f, indent=2)
    print(f"\nSaved: {OUT / 'ceci_results.json'}")

if __name__ == "__main__":
    main()
"""


def print_plan():
    print("=" * 70)
    print("EC2 ORCHESTRATOR: Gemma-4-2B CECI Pipeline")
    print(f"  Budget: $100")
    print(f"  Instance: g6e.xlarge (L40S, 46GB VRAM)")
    print(f"  Spot price: ~$0.45/hr")
    print("=" * 70)
    print()
    print("STEP 1: Setup (10 min) --- launch instance, install deps")
    print("STEP 2: Math LoRA (4 hrs) --- train on GSM8K + MATH")
    print("STEP 3: Lang LoRA (4 hrs) --- train on WikiText + books")
    print("STEP 4: CECI splice (30 min) --- k=768 crossover")
    print("STEP 5: Benchmark (2 hrs) --- compare all models")
    print("STEP 6: Publish (15 min) --- Ollama + paper update")
    print()
    print("ESTIMATED TOTAL: ~11 hrs = ~$5.00 on spot")
    print()


if __name__ == "__main__":
    print_plan()
