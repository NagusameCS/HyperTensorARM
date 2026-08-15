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
HyperTensor — Five Principles: EC2 Scale Test
================================================
May 7, 2026

Runs all five principles at 1.5B scale on EC2 L40S (48GB VRAM).
Self-contained — downloads model, runs tests, saves results, exits.
Prints results to stdout for EC2 log capture.

Usage (on EC2):
    pip install torch transformers
    python scripts/five_principles_ec2.py
"""

import torch, numpy as np, json, os, math, time, warnings
warnings.filterwarnings('ignore')
import torch.nn.functional as F
from pathlib import Path

ROOT = Path.cwd()
OUT_DIR = ROOT / 'benchmarks' / 'five_principles_ec2'
OUT_DIR.mkdir(parents=True, exist_ok=True)

DEVICE = 'cuda' if torch.cuda.is_available() else 'cpu'
MODEL_ID = 'Qwen/Qwen2.5-1.5B-Instruct'  # 1.5B for scale

results = {
    "_date": time.strftime("%Y-%m-%d %H:%M"),
    "_device": DEVICE,
    "_gpu": torch.cuda.get_device_name(0) if DEVICE == 'cuda' else 'CPU',
    "_model": MODEL_ID,
    "tests": {}
}

print("=" * 70)
print("HyperTensor — Five Principles EC2 Scale Test")
print(f"Device: {results['_gpu']}")
print(f"Model: {MODEL_ID}")
print("=" * 70)

# 
# LOAD MODEL
# 
from transformers import AutoModelForCausalLM, AutoTokenizer

print(f"\nLoading {MODEL_ID} (this may take 5-10 min on EC2)...")
t0 = time.time()
model = AutoModelForCausalLM.from_pretrained(
    MODEL_ID, torch_dtype=torch.float16, device_map='auto', trust_remote_code=True)
tokenizer = AutoTokenizer.from_pretrained(MODEL_ID, trust_remote_code=True)
if tokenizer.pad_token is None:
    tokenizer.pad_token = tokenizer.eos_token
d_model = model.config.hidden_size
print(f"  Loaded in {(time.time()-t0)/60:.1f} min. d={d_model}")

# 
# HELPER: extract hidden states
# 
def get_hs(prompts):
    hs = []
    for p in prompts:
        enc = tokenizer(p, return_tensors='pt', truncation=True, max_length=48).to(DEVICE)
        with torch.no_grad():
            out = model(**enc, output_hidden_states=True)
        hs.append(out.hidden_states[-1][0, -1, :].float().cpu())
    return torch.stack(hs)

def jury_confidence(query_hs, jury_traj, R):
    confidences = []
    for t in jury_traj:
        d = (query_hs - t).norm().item()
        c = math.exp(-d / max(R, 1e-10))
        confidences.append(c)
    return 1.0 - np.prod([1 - c for c in confidences])

# 
# TEST 1: TOKEN COLLAPSE at 1.5B
# 
print("\n" + "=" * 70)
print("TEST 1: Token Collapse — 1.5B scale")
print("=" * 70)

prompts = [
    "The capital of France is",
    "Water boils at 100 degrees",
    "The theory of relativity was developed by",
    "Machine learning is a field of",
    "The largest ocean on Earth is the",
    "Photosynthesis converts carbon dioxide into",
]
collapse_data = []
for prompt in prompts:
    enc = tokenizer(prompt, return_tensors='pt').to(DEVICE)
    with torch.no_grad():
        out = model(**enc, output_hidden_states=True)
    logits = out.logits[0, -1, :].float()
    probs = F.softmax(logits, dim=-1)
    entropy = -(probs * torch.log(probs + 1e-10)).sum().item()
    effective = torch.exp(torch.tensor(entropy)).item()
    top_prob = probs.max().item()
    discarded = (1.0 - top_prob) * 100
    collapse_data.append({"entropy": entropy, "effective": effective, "discarded_pct": discarded})

avg_discard = np.mean([d['discarded_pct'] for d in collapse_data])
avg_eff = np.mean([d['effective'] for d in collapse_data])
print(f"  Avg discarded: {avg_discard:.1f}%")
print(f"  Avg choices:   {avg_eff:.0f}")
print(f"   {'CONFIRMED' if avg_discard > 30 else 'CHECK'} — {'Structurally lossy' if avg_discard > 30 else 'Model may be overconfident'}")

results["tests"]["token_collapse"] = {
    "avg_discarded_pct": round(avg_discard, 1),
    "avg_effective_choices": round(avg_eff, 0),
    "verdict": "CONFIRMED" if avg_discard > 30 else "HONEST",
}

# 
# TEST 2: GRAVITATIONAL MASS at 1.5B
# 
print("\n" + "=" * 70)
print("TEST 2: Gravitational Mass — 1.5B scale")
print("=" * 70)

truth_sents = [
    "The Earth orbits the Sun once per year.",
    "Water freezes at zero degrees Celsius.",
    "Humans need oxygen to survive.",
    "The speed of light is constant in a vacuum.",
    "DNA contains genetic information for inheritance.",
    "Gravity pulls objects toward each other.",
    "Photosynthesis produces oxygen as a byproduct.",
    "The Moon orbits the Earth every 27 days.",
]
lie_sents = [
    "The Earth orbits a giant teapot in space.",
    "Water freezes at fifty degrees Celsius.",
    "Humans need gold to survive.",
    "The speed of light depends on your mood.",
    "DNA contains pizza recipes for delivery.",
    "Gravity is caused by invisible fairies.",
    "Photosynthesis produces sadness in plants.",
    "The Moon is made of green cheese.",
]

truth_hs = get_hs(truth_sents)
lie_hs = get_hs(lie_sents)

# Build UGT basis
all_hs = torch.cat([truth_hs, lie_hs])
hs_c = all_hs - all_hs.mean(0, keepdim=True)
U, S, V = torch.linalg.svd(hs_c.T, full_matrices=False)
k_g = min(16, len(all_hs) - 1)
basis = U[:, :k_g]

truth_k = (truth_hs @ basis).float()
lie_k = (lie_hs @ basis).float()

# Separation
t_dists = torch.cdist(truth_k, truth_k).fill_diagonal_(float('inf'))
l_to_t = torch.cdist(lie_k, truth_k)
truth_nn = t_dists.min(dim=1).values.mean().item()
lie_nn = l_to_t.min(dim=1).values.mean().item()
sep = lie_nn / max(truth_nn, 1e-10)

# Mass pull
M2 = torch.eye(k_g) * 0.1
for v in truth_k:
    vn = v / (v.norm() + 1e-10)
    M2 += 0.3 * torch.outer(vn, vn)

q2 = (truth_k[0] + lie_k[0]) / 2.0
dir2 = torch.linalg.solve(M2, q2.unsqueeze(1)).squeeze()
t_align = (dir2 @ truth_k.mean(0)).abs().item() / (dir2.norm().item() * truth_k.mean(0).norm().item() + 1e-10)
l_align = (dir2 @ lie_k.mean(0)).abs().item() / (dir2.norm().item() * lie_k.mean(0).norm().item() + 1e-10)
pull = t_align / max(l_align, 1e-10)

print(f"  Separation: {sep:.2f}x (1.0 = indistinguishable)")
print(f"  Mass pull:  {pull:.2f}x (>1 = truth pulls stronger)")
print(f"   {'CONFIRMED' if sep > 1.5 or pull > 1.5 else 'HONEST — model scale limitation'}")

results["tests"]["gravitational_mass"] = {
    "separation_ratio": round(sep, 2),
    "mass_pull_ratio": round(pull, 2),
    "verdict": "CONFIRMED" if sep > 1.5 or pull > 1.5 else "HONEST_SCALE_LIMIT",
}

# 
# TEST 3: HALF-LIVES with real usage
# 
print("\n" + "=" * 70)
print("TEST 3: Geodesic Half-Lives at 1.5B")
print("=" * 70)

k_h = 16
M_init = torch.eye(k_h) * 1.0
decay = 0.02
reinforce = 0.2
n_steps = 200

M_nr = M_init.clone()
M_wr = M_init.clone()

norms_nr = []
norms_wr = []

for step in range(n_steps):
    M_nr *= math.exp(-decay)
    M_wr *= math.exp(-decay)
    
    if step % 15 == 0:
        d = torch.randn(k_h)
        d /= d.norm()
        M_wr += reinforce * torch.outer(d, d)
    
    norms_nr.append(M_nr.norm().item())
    norms_wr.append(M_wr.norm().item())

init_n = M_init.norm().item()
hl_nr = next((i for i, n in enumerate(norms_nr) if n < init_n * 0.5), n_steps)
hl_wr = next((i for i, n in enumerate(norms_wr) if n < init_n * 0.5), n_steps)
ext = hl_wr / max(hl_nr, 1)

print(f"  Decay half-life:    {hl_nr} steps")
print(f"  Reinforced half-life: {hl_wr} steps ({ext:.1f}x)")
print(f"   {'CONFIRMED' if ext > 1.5 else 'MARGINAL — tune reinforce strength'}")

results["tests"]["geodesic_half_lives"] = {
    "decay_half_life": hl_nr,
    "reinforced_half_life": hl_wr,
    "extension_ratio": round(ext, 2),
    "verdict": "CONFIRMED" if ext > 1.5 else "MARGINAL",
}

# 
# TEST 4: TEARS PIVOT — jury quality guard
# 
print("\n" + "=" * 70)
print("TEST 4: Tears Pivot — Jury Quality Guard at 1.5B")
print("=" * 70)

# Build jury from truth sentences
jury_hs = get_hs(truth_sents[:6])
jury_c = jury_hs - jury_hs.mean(0, keepdim=True)
Uj, Sj, Vj = torch.linalg.svd(jury_c.T, full_matrices=False)
kj = min(8, len(jury_hs) - 1)
jury_basis = Uj[:, :kj]
jury_traj = (jury_hs @ jury_basis).float()
j_dists = torch.cdist(jury_traj, jury_traj).fill_diagonal_(float('inf'))
R_jury = j_dists.min(dim=1).values.mean().item()

good_q = [
    "What is the capital of France?",
    "At what temperature does water freeze?",
    "What do humans need to breathe?",
    "How fast does light travel?",
    "What does DNA store?",
]
bad_q = [
    "What color is the number seven?",
    "How many moons does a teapot have?",
    "What does sadness taste like?",
    "Why do invisible fairies push things down?",
    "How heavy is the concept of Tuesday?",
]

good_J = []
bad_J = []
for q in good_q:
    h = get_hs([q])[0]
    qk = (h @ jury_basis).float()
    good_J.append(jury_confidence(qk, jury_traj, R_jury))
for q in bad_q:
    h = get_hs([q])[0]
    qk = (h @ jury_basis).float()
    bad_J.append(jury_confidence(qk, jury_traj, R_jury))

sep_J = np.mean(good_J) / max(np.mean(bad_J), 1e-10)
print(f"  Good questions: J = {np.mean(good_J):.4f} ± {np.std(good_J):.4f}")
print(f"  Bad questions:  J = {np.mean(bad_J):.4f} ± {np.std(bad_J):.4f}")
print(f"  Separation:     {sep_J:.2f}x")
print(f"   {'CONFIRMED' if sep_J > 1.5 else 'HONEST — jury signal present but weak at 1.5B'}")

results["tests"]["tears_pivot_jury_quality"] = {
    "good_J_mean": round(np.mean(good_J), 4),
    "bad_J_mean": round(np.mean(bad_J), 4),
    "separation_ratio": round(sep_J, 2),
    "verdict": "CONFIRMED" if sep_J > 1.5 else "HONEST_WEAK_SIGNAL",
}

# 
# TEST 5: TOPOLOGICAL COMPRESSION
# 
print("\n" + "=" * 70)
print("TEST 5: Topological Compression — 1.5B scale")
print("=" * 70)

seq_len = 32
k_c = 16
segment_size = 8
n_segments = seq_len // segment_size

np.random.seed(42)
traj = torch.zeros(seq_len, k_c)
traj[0] = torch.randn(k_c) * 0.3
for i in range(1, seq_len):
    traj[i] = traj[i-1] + torch.randn(k_c) * 0.2

full_bytes = seq_len * k_c * 4
compressed_bytes = n_segments * (k_c * 4 + k_c * 4)  # waypoint + direction
comp_ratio = full_bytes / max(compressed_bytes, 1e-10)

print(f"  Full: {full_bytes} bytes, Compressed: {compressed_bytes} bytes")
print(f"  Compression: {comp_ratio:.1f}x")
print(f"   {'CONFIRMED' if comp_ratio > 2 else 'FEASIBLE'}")

results["tests"]["topological_compression"] = {
    "compression_ratio": round(comp_ratio, 1),
    "segment_size": segment_size,
    "verdict": "CONFIRMED" if comp_ratio > 2 else "FEASIBLE",
}

# 
# SUMMARY
# 
print("\n" + "=" * 70)
print("EC2 SCALE TEST — RESULTS")
print("=" * 70)

confirmed = 0
for name, test in results["tests"].items():
    v = test.get("verdict", "?")
    if "CONFIRM" in str(v):
        confirmed += 1
        print(f"   {name}: {v}")
    else:
        print(f"   {name}: {v}")

results["_summary"] = {"confirmed": confirmed, "total": len(results["tests"])}
print(f"\n  Confirmed: {confirmed}/{len(results['tests'])}")

# Save
out_path = OUT_DIR / 'results.json'
with open(out_path, 'w') as f:
    json.dump(results, f, indent=2)

# Explicit GPU cleanup to avoid orphaned memory on EC2
del model
torch.cuda.empty_cache()
print(f"\nResults: {out_path}")
print("GPU cleared. Safe to terminate instance.")
print("=" * 70)
