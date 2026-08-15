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
Dedicated Single-Skill Model Training Pipeline (Paper X Prerequisite).

Generates training configurations for two dedicated models:
  Model M (Math): trained on GSM8K + ProofNet + MATH + code
  Model L (Language): trained on WikiText + Books + dialogue

Uses HuggingFace datasets to prepare filtered training corpora
and emits a training configuration for use with standard
fine-tuning frameworks (Axolotl, Unsloth, or raw HF Trainer).

Usage:
  python scripts/train_dedicated_models.py --config math --out configs/math_model
  python scripts/train_dedicated_models.py --config language --out configs/language_model
"""

from __future__ import annotations

import argparse
import json
import os
from pathlib import Path


# ===========================================================================
# Model configuration
# ===========================================================================

BASE_CONFIG = {
    "base_model": "HuggingFaceTB/SmolLM2-135M",  # or meta-llama/Llama-3.1-8B
    "architecture": "LlamaForCausalLM",
    "max_seq_length": 2048,
    "dtype": "bfloat16",
    "use_flash_attention_2": True,
    "training": {
        "per_device_train_batch_size": 8,
        "gradient_accumulation_steps": 4,
        "learning_rate": 2e-5,
        "warmup_steps": 100,
        "max_steps": 50000,
        "save_steps": 5000,
        "eval_steps": 1000,
        "logging_steps": 100,
        "weight_decay": 0.01,
        "lr_scheduler_type": "cosine",
        "optim": "adamw_8bit",
        "bf16": True,
        "gradient_checkpointing": True,
    },
}

MATH_CONFIG = {
    **BASE_CONFIG,
    "description": "Dedicated Math Model --- trained exclusively on mathematical reasoning data",
    "output_name": "smollm2-135m-math-only",
    "datasets": [
        {
            "name": "gsm8k",
            "path": "gsm8k",
            "split": "train",
            "filter": "math",
            "max_samples": 8000,
            "format": "### Question: {question}\n### Answer: {answer}",
        },
        {
            "name": "math_dataset",
            "path": "HuggingFaceH4/MATH-500",  # or math_dataset from HF
            "split": "train",
            "filter": None,
            "max_samples": 5000,
        },
    ],
    "data_filters": {
        "exclude_patterns": [
            r"(?i)once upon a time",
            r"(?i)chapter \d+",
            r"^\s*$",  # empty lines
        ],
        "include_patterns": [
            r"\d+",  # must contain numbers
            r"[+\-*/=<>]",  # must contain math operators
        ],
    },
}

LANGUAGE_CONFIG = {
    **BASE_CONFIG,
    "description": "Dedicated Language Model --- trained exclusively on natural language data",
    "output_name": "smollm2-135m-language-only",
    "datasets": [
        {
            "name": "wikitext",
            "path": "wikitext",
            "config": "wikitext-103-raw-v1",
            "split": "train",
            "filter": "language",
            "max_samples": 50000,
        },
        {
            "name": "bookcorpus",
            "path": "bookcorpus",  # or bookcorpusopen
            "split": "train",
            "filter": "language",
            "max_samples": 20000,
        },
    ],
    "data_filters": {
        "exclude_patterns": [
            r"\b\d{4,}\b",  # long number sequences
            r"[+\-*/=\^]{2,}",  # math operators
            r"\\begin\{",  # LaTeX
            r"\\frac\{",  # LaTeX fractions
            r"\$.*\$",  # inline math
        ],
        "include_patterns": [
            r"[a-zA-Z]{3,}",  # must contain words
        ],
    },
}


# ===========================================================================
# Training script generator
# ===========================================================================

def generate_training_script(config: dict, output_dir: Path) -> str:
    """Generate a bash training script for the given configuration."""
    output_dir.mkdir(parents=True, exist_ok=True)

    script = f"""#!/bin/bash
# Dedicated {'Math' if 'math' in config['output_name'] else 'Language'} Model Training
# Generated by scripts/train_dedicated_models.py

set -euo pipefail

MODEL="{config['base_model']}"
OUTPUT="{config['output_name']}"
EPOCHS=3
BATCH_SIZE={config['training']['per_device_train_batch_size']}
GRAD_ACCUM={config['training']['gradient_accumulation_steps']}
MAX_STEPS={config['training']['max_steps']}

echo "Training $OUTPUT from $MODEL"
echo "Config: {config['description']}"

# Use Axolotl or direct HF Trainer
# Option 1: Axolotl (recommended for efficient training)
# axolotl train configs/{config['output_name']}.yml

# Option 2: Direct HuggingFace Trainer
python -m torch.distributed.run --nproc_per_node=1 scripts/train_single_skill.py \\
    --model_name_or_path "$MODEL" \\
    --output_dir "./outputs/$OUTPUT" \\
    --per_device_train_batch_size $BATCH_SIZE \\
    --gradient_accumulation_steps $GRAD_ACCUM \\
    --max_steps $MAX_STEPS \\
    --learning_rate {config['training']['learning_rate']} \\
    --warmup_steps {config['training']['warmup_steps']} \\
    --bf16 \\
    --gradient_checkpointing \\
    --save_strategy steps \\
    --save_steps {config['training']['save_steps']} \\
    --logging_steps {config['training']['logging_steps']} \\
    --dataset_config "{output_dir / 'dataset_config.json'}"

echo "Training complete. Model saved to ./outputs/$OUTPUT"
"""

    script_path = output_dir / "train.sh"
    script_path.write_text(script)
    script_path.chmod(0o755)
    return str(script_path)


# ===========================================================================
# Dataset config generator
# ===========================================================================

def generate_dataset_config(config: dict, output_dir: Path) -> str:
    """Generate a dataset configuration JSON for the training script."""
    dataset_config = {
        "description": config["description"],
        "datasets": [],
        "filters": config.get("data_filters", {}),
        "max_total_tokens": config["training"]["max_steps"]
                           * config["training"]["per_device_train_batch_size"]
                           * config["training"]["gradient_accumulation_steps"]
                           * config.get("max_seq_length", 2048),
    }

    for ds in config["datasets"]:
        dataset_config["datasets"].append({
            "name": ds["name"],
            "path": ds["path"],
            "split": ds["split"],
            "max_samples": ds["max_samples"],
            "format": ds.get("format", "{text}"),
            "filter": ds.get("filter"),
        })

    config_path = output_dir / "dataset_config.json"
    config_path.write_text(json.dumps(dataset_config, indent=2))
    return str(config_path)


# ===========================================================================
# Data preparation script
# ===========================================================================

def generate_data_prep_script(config: dict, output_dir: Path) -> str:
    """Generate a Python script to prepare and filter the training data."""
    is_math = "math" in config["output_name"]
    filter_type = "math" if is_math else "language"

    script = f'''#!/usr/bin/env python3
"""Prepare {filter_type}-only training data for dedicated model training."""
import json, re, os
from datasets import load_dataset, concatenate_datasets

OUTPUT_DIR = "{output_dir}"
os.makedirs(OUTPUT_DIR, exist_ok=True)

exclude = {json.dumps(config["data_filters"]["exclude_patterns"])}
include = {json.dumps(config["data_filters"]["include_patterns"])}

def filter_{filter_type}(text: str) -> bool:
    """Return True if text is pure {filter_type} content."""
    if not text or len(text.strip()) < 20:
        return False
    # Must match at least one include pattern
    if not any(re.search(p, text) for p in include):
        return False
    # Must not match any exclude pattern
    if any(re.search(p, text, re.IGNORECASE) for p in exclude):
        return False
    return True

all_data = []
for ds_info in {json.dumps(config["datasets"])}:
    print(f"Loading {{ds_info['name']}}...")
    try:
        ds = load_dataset(ds_info["path"], split=ds_info["split"], trust_remote_code=True)
        # Format if needed
        fmt = ds_info.get("format", "{{text}}")
        filtered = []
        for row in ds:
            if len(filtered) >= ds_info.get("max_samples", 50000):
                break
            text = fmt.format(**row) if fmt else row.get("text", "")
            if filter_{filter_type}(text):
                filtered.append({{"text": text}})
        print(f"  {{ds_info['name']}}: {{len(filtered)}} filtered samples")
        all_data.extend(filtered)
    except Exception as e:
        print(f"  {{ds_info['name']}}: SKIP ({{e}})")

# Save
output_path = os.path.join(OUTPUT_DIR, "{filter_type}_only_train.jsonl")
with open(output_path, "w") as f:
    for item in all_data:
        f.write(json.dumps(item) + "\\n")

print(f"\\nTotal: {{len(all_data)}} samples -> {{output_path}}")
print(f"Estimated tokens: ~{{len(all_data) * 200}} (rough)")
'''

    script_path = output_dir / "prepare_data.py"
    script_path.write_text(script)
    return str(script_path)


# ===========================================================================
# Main
# ===========================================================================

def main():
    ap = argparse.ArgumentParser(
        description="Dedicated Single-Skill Model Training Pipeline"
    )
    ap.add_argument("--config", required=True, choices=["math", "language"],
                    help="Which dedicated model to configure")
    ap.add_argument("--out", default=None,
                    help="Output directory for configs")
    ap.add_argument("--base-model", default="HuggingFaceTB/SmolLM2-135M",
                    help="Base model for training")
    ap.add_argument("--max-steps", type=int, default=50000)
    args = ap.parse_args()

    config = MATH_CONFIG if args.config == "math" else LANGUAGE_CONFIG
    config["base_model"] = args.base_model
    config["training"]["max_steps"] = args.max_steps

    out_dir = Path(args.out) if args.out else Path(f"configs/{config['output_name']}")

    # Generate all artifacts
    dataset_path = generate_dataset_config(config, out_dir)
    data_prep_path = generate_data_prep_script(config, out_dir)
    train_path = generate_training_script(config, out_dir)

    # Save config
    with open(out_dir / "model_config.json", "w") as f:
        json.dump(config, f, indent=2)

    print(f"=== Dedicated {args.config.upper()} Model Configuration ===")
    print(f"  Base: {config['base_model']}")
    print(f"  Output: {config['output_name']}")
    print(f"  Datasets: {[d['name'] for d in config['datasets']]}")
    print(f"  Max steps: {config['training']['max_steps']}")
    print(f"  Estimated tokens: ~{config['training']['max_steps'] * config['training']['per_device_train_batch_size'] * config['training']['gradient_accumulation_steps'] * config.get('max_seq_length', 2048):,}")
    print()
    print(f"  Generated:")
    print(f"    {out_dir / 'model_config.json'}")
    print(f"    {out_dir / 'dataset_config.json'}")
    print(f"    {data_prep_path}")
    print(f"    {train_path}")
    print()
    print(f"  Next steps:")
    print(f"    1. Review dataset_config.json and adjust filters")
    print(f"    2. Run: python {data_prep_path}")
    print(f"    3. Run: bash {train_path}")
    print(f"    4. Model saved to ./outputs/{config['output_name']}")
    print(f"    5. Quantize to GGUF: python llama.cpp/convert.py ...")


if __name__ == "__main__":
    main()
