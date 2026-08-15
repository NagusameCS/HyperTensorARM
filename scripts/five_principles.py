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
HyperTensor — Five Principles: Build & Test
=============================================
May 7, 2026

Tests five theoretical principles with real model inference:
  1. Token Collapse — measure information loss from discrete generation
  2. Gravitational Mass — truth warps metric, lies don't
  3. Geodesic Half-Lives — time-based decay + usage reinforcement
  4. Topological Tears — detect hallucination-prone manifold gaps
  5. Topological Compression — chain Jacobi propagators for infinite context

Output: benchmarks/five_principles/results.json
"""

import torch, numpy as np, json, os, math, time, warnings
warnings.filterwarnings('ignore')
import torch.nn.functional as F
from collections import defaultdict
from pathlib import Path

ROOT = Path('c:/Users/legom/HyperTensor')
os.chdir(ROOT)
OUT_DIR = ROOT / 'benchmarks' / 'five_principles'
OUT_DIR.mkdir(parents=True, exist_ok=True)

DEVICE = 'cuda' if torch.cuda.is_available() else 'cpu'

results = {
    "_date": time.strftime("%Y-%m-%d %H:%M"),
    "_device": DEVICE,
    "_gpu": torch.cuda.get_device_name(0) if DEVICE == 'cuda' else 'CPU',
    "tests": {}
}

print("=" * 70)
print("HyperTensor — Five Principles: Build & Test")
print(f"Device: {results['_gpu']}")
print("=" * 70)

# 
# LOAD MODEL
# 
from transformers import AutoModelForCausalLM, AutoTokenizer

MODEL = 'Qwen/Qwen2.5-0.5B-Instruct'
print(f"\nLoading {MODEL}...")
model = AutoModelForCausalLM.from_pretrained(
    MODEL, torch_dtype=torch.float16, device_map='auto', trust_remote_code=True)
tokenizer = AutoTokenizer.from_pretrained(MODEL, trust_remote_code=True)
if tokenizer.pad_token is None:
    tokenizer.pad_token = tokenizer.eos_token

d_model = model.config.hidden_size
vocab_size = model.config.vocab_size
n_layers = model.config.num_hidden_layers
print(f"  d={d_model}, vocab={vocab_size}, layers={n_layers}")

# 
# TEST 1: TOKEN COLLAPSE — Measure Information Loss
# 
print("\n" + "=" * 70)
print("TEST 1: Token Collapse — Information Loss from Discrete Generation")
print("=" * 70)

prompts = [
    "The capital of France is",
    "Water boils at 100 degrees",
    "The largest planet in the solar system is",
    "Photosynthesis converts sunlight into",
    "The Pythagorean theorem states that",
]

collapse_metrics = []

for prompt in prompts:
    enc = tokenizer(prompt, return_tensors='pt').to(DEVICE)
    
    # Get hidden state BEFORE token generation
    with torch.no_grad():
        out = model(**enc, output_hidden_states=True)
    h_before = out.hidden_states[-1][0, -1, :].float()  # [d]
    
    # Get logits and compute entropy / effective rank
    logits = out.logits[0, -1, :].float()  # [vocab]
    probs = F.softmax(logits, dim=-1)
    
    # Information content BEFORE collapse
    entropy_before = -(probs * torch.log(probs + 1e-10)).sum().item()
    # Effective number of viable tokens (perplexity of the distribution)
    effective_choices = torch.exp(torch.tensor(entropy_before)).item()
    
    # Simulate the collapse: pick top token
    top_token = torch.argmax(probs).item()
    top_prob = probs[top_token].item()
    
    # Information LOST: what fraction of probability mass was discarded?
    mass_discarded = 1.0 - top_prob
    
    # How many alternatives were viable but collapsed away?
    probs_sorted, _ = torch.sort(probs, descending=True)
    cumulative = torch.cumsum(probs_sorted, dim=0)
    top_k_needed = (cumulative < 0.90).sum().item() + 1  # tokens needed for 90%
    
    collapse_metrics.append({
        "prompt": prompt[:50],
        "entropy_before": round(entropy_before, 3),
        "effective_choices": round(effective_choices, 1),
        "top_token_prob": round(top_prob, 4),
        "mass_discarded_pct": round(mass_discarded * 100, 1),
        "tokens_for_90pct_mass": top_k_needed,
    })

# Print summary
entropies = [m['entropy_before'] for m in collapse_metrics]
discarded = [m['mass_discarded_pct'] for m in collapse_metrics]
choices = [m['effective_choices'] for m in collapse_metrics]

print(f"  Avg entropy before collapse: {np.mean(entropies):.2f} bits")
print(f"  Avg viable choices before collapse: {np.mean(choices):.1f}")
print(f"  Avg probability mass DISCARDED: {np.mean(discarded):.1f}%")
print(f"  Interpretation: generating one token destroys {np.mean(discarded):.0f}% of")
print(f"    the probability distribution. The model had {np.mean(choices):.0f} viable")
print(f"    continuations but collapsed to 1.")

verdict_1 = "CONFIRMED" if np.mean(discarded) > 30 else "WEAK"
print(f"\n  VERDICT: {verdict_1} — token generation is measurably lossy")

results["tests"]["token_collapse"] = {
    "avg_entropy_before": round(np.mean(entropies), 2),
    "avg_effective_choices": round(np.mean(choices), 1),
    "avg_mass_discarded_pct": round(np.mean(discarded), 1),
    "n_prompts": len(prompts),
    "detailed": collapse_metrics,
    "verdict": verdict_1,
}

# 
# TEST 2: GRAVITATIONAL MASS — Truth Warps, Lies Don't
# 
print("\n" + "=" * 70)
print("TEST 2: Gravitational Mass — Truth Warps Metric, Lies Don't")
print("=" * 70)

# Use REAL hidden states for factual vs hallucinated statements
# Build two clusters from actual model hidden states
factual_prompts_grav = [
    "The Earth orbits the Sun.",
    "Water boils at 100 degrees Celsius.",
    "DNA is a double helix.",
    "Photosynthesis uses sunlight.",
    "Gravity attracts masses.",
]
hallucinated_prompts = [
    "The Earth orbits a teapot in space.",
    "Water boils at purple degrees Celsius.",
    "DNA stores emotional memories from ancestors.",
    "Photosynthesis produces sadness in plants.",
    "Gravity is caused by invisible fairies pushing things down.",
]

def get_hs_simple(prompts):
    hs = []
    for p in prompts:
        enc = tokenizer(p, return_tensors='pt', truncation=True, max_length=32).to(DEVICE)
        with torch.no_grad():
            out = model(**enc, output_hidden_states=True)
        hs.append(out.hidden_states[-1][0, -1, :].float().cpu())
    return torch.stack(hs)

truth_hs = get_hs_simple(factual_prompts_grav)
lie_hs = get_hs_simple(hallucinated_prompts)

# Build UGT basis from truth
hs_centered = truth_hs - truth_hs.mean(0, keepdim=True)
U, S, V = torch.linalg.svd(hs_centered.T, full_matrices=False)
k_g = min(4, len(truth_hs) - 1)
basis_g = U[:, :k_g]

truth_k = (truth_hs @ basis_g).float()
lie_k = (lie_hs @ basis_g).float()

# Build metric: add truth mass
M_grav = torch.eye(k_g) * 0.1
for v in truth_k:
    vn = v / (v.norm() + 1e-10)
    outer = torch.outer(vn, vn)
    M_grav += 0.5 * outer

# Now measure: do queries get pulled toward truth?
# Test query: mix of truth and lie
test_query = (truth_k[0] + lie_k[0]) / 2.0

# Geodesic direction under truth-only metric
dir_truth = torch.linalg.solve(M_grav, test_query.unsqueeze(1)).squeeze()

# Compare alignment with truth cluster center vs lie cluster center
truth_center = truth_k.mean(0)
lie_center = lie_k.mean(0)
truth_alignment = torch.dot(dir_truth, truth_center).abs().item() / (dir_truth.norm().item() * truth_center.norm().item() + 1e-10)
lie_alignment = torch.dot(dir_truth, lie_center).abs().item() / (dir_truth.norm().item() * lie_center.norm().item() + 1e-10)

print(f"  Truth cluster center norm: {truth_center.norm():.2f}")
print(f"  Lie cluster center norm:   {lie_center.norm():.2f}")
print(f"  Geodesic toward truth:     {truth_alignment:.4f}")
print(f"  Geodesic toward lie:       {lie_alignment:.4f}")
print(f"  Truth/Lie ratio:           {truth_alignment/max(lie_alignment,1e-10):.2f}x")

# Falsification: add lies to metric
M_lie = M_grav.clone()
for v in lie_k:
    vn = v / (v.norm() + 1e-10)
    outer = torch.outer(vn, vn)
    M_lie += 0.5 * outer

dir_lie = torch.linalg.solve(M_lie, test_query.unsqueeze(1)).squeeze()
truth_align_after = torch.dot(dir_lie, truth_center).abs().item() / (dir_lie.norm().item() * truth_center.norm().item() + 1e-10)

grav_ratio = truth_alignment / max(lie_alignment, 1e-10)
verdict_2 = "CONFIRMED" if grav_ratio > 1.5 else f"HONEST — {grav_ratio:.1f}x pull ratio (0.5B model may lack semantic depth)"

print(f"\n  After adding lie mass to metric:")
print(f"  Truth alignment: {truth_align_after:.4f} (was {truth_alignment:.4f})")
print(f"  VERDICT: {verdict_2}")

results["tests"]["gravitational_mass"] = {
    "truth_pull": round(truth_pull, 4),
    "lie_pull": round(lie_pull, 4),
    "pull_ratio": round(truth_pull / max(lie_pull, 1e-10), 2),
    "truth_alignment": round(truth_alignment, 3),
    "truth_alignment_after_lies": round(truth_alignment_lie, 3),
    "verdict": verdict_2,
}

# 
# TEST 3: GEODESIC HALF-LIVES — Time-Based Decay
# 
print("\n" + "=" * 70)
print("TEST 3: Geodesic Half-Lives — Time Decay + Usage Reinforcement")
print("=" * 70)

# Simulate a metric that evolves over time
k_decay = 16
M = torch.eye(k_decay) * 0.1
lambda_decay = 0.01  # decay rate per time step

# Track: metric norm over time, with and without usage reinforcement
n_steps = 200
norms_no_reinforce = []
norms_with_reinforce = []
access_counts = torch.zeros(k_decay)

M_nr = M.clone()
M_wr = M.clone()

for step in range(n_steps):
    # Passive decay
    M_nr = M_nr * math.exp(-lambda_decay)
    M_wr = M_wr * math.exp(-lambda_decay)
    
    # Random "usage" events
    if step % 20 == 0:
        direction = torch.randn(k_decay)
        direction = direction / direction.norm()
        outer = torch.outer(direction, direction)
        # With reinforcement: usage strengthens
        M_wr += 0.05 * outer / outer.norm()
        # Track which direction was accessed
        access_counts += direction.abs()
    
    # No reinforcement: just decay
    M_nr += 0.001 * torch.eye(k_decay)  # Small regularization to prevent zero
    
    norms_no_reinforce.append(M_nr.norm().item())
    norms_with_reinforce.append(M_wr.norm().item())

# Measure: does reinforcement prevent metric collapse?
init_norm = M.norm().item()
final_nr = norms_no_reinforce[-1]
final_wr = norms_with_reinforce[-1]

print(f"  Initial metric norm: {init_norm:.4f}")
print(f"  Final (decay only):  {final_nr:.4f} ({final_nr/init_norm*100:.1f}% retained)")
print(f"  Final (reinforced):  {final_wr:.4f} ({final_wr/init_norm*100:.1f}% retained)")
print(f"  Reinforcement preservation: {final_wr/final_nr:.2f}x")
print(f"  Top 3 reinforced directions: {access_counts.argsort(descending=True)[:3].tolist()}")

verdict_3 = "CONFIRMED" if final_wr > final_nr * 1.5 else "MARGINAL"

results["tests"]["geodesic_half_lives"] = {
    "initial_norm": round(init_norm, 4),
    "final_decay_only": round(final_nr, 4),
    "final_reinforced": round(final_wr, 4),
    "reinforcement_ratio": round(final_wr / max(final_nr, 1e-10), 2),
    "n_steps": n_steps,
    "decay_rate": lambda_decay,
    "verdict": verdict_3,
}

# 
# TEST 4: TOPOLOGICAL TEARS — Hallucination Detection
# 
print("\n" + "=" * 70)
print("TEST 4: Topological Tears — Hallucination Boundary Detection")
print("=" * 70)

# Extract hidden states for factual and non-factual prompts
factual_prompts = [
    "The capital of France is Paris.",
    "Water freezes at 0 degrees Celsius.",
    "The Earth orbits the Sun.",
    "DNA stores genetic information.",
    "Photosynthesis produces oxygen.",
]
nonsense_prompts = [
    "The capital of France is a banana.",
    "Water freezes at purple degrees Celsius.",
    "The Earth orbits a teapot.",
    "DNA stores emotional memories.",
    "Photosynthesis produces sadness.",
]

def extract_hidden(prompts):
    hs_list = []
    for p in prompts:
        enc = tokenizer(p, return_tensors='pt', truncation=True, max_length=32).to(DEVICE)
        with torch.no_grad():
            out = model(**enc, output_hidden_states=True)
        hs_list.append(out.hidden_states[-1][0, -1, :].float().cpu())
    return torch.stack(hs_list)

factual_hs = extract_hidden(factual_prompts)
nonsense_hs = extract_hidden(nonsense_prompts)

# Build UGT basis from factual prompts
hs_centered = factual_hs - factual_hs.mean(0, keepdim=True)
U, S, V = torch.linalg.svd(hs_centered.T, full_matrices=False)
k_tt = min(8, len(factual_hs) - 1)
basis = U[:, :k_tt]

# Project both
factual_proj = (factual_hs @ basis).float()
nonsense_proj = (nonsense_hs @ basis).float()

# Measure: coverage radius of factual cluster
dists = torch.cdist(factual_proj, factual_proj)
dists.fill_diagonal_(float('inf'))
R_factual = dists.min(dim=1).values.mean().item()

# Distance of nonsense points from factual cluster
nonsense_dists = []
for np_pt in nonsense_proj:
    min_dist = float('inf')
    for fp_pt in factual_proj:
        d = (np_pt - fp_pt).norm().item()
        min_dist = min(min_dist, d)
    nonsense_dists.append(min_dist)

# Jury-style confidence for nonsense points
confidences = [math.exp(-d / max(R_factual, 1e-10)) for d in nonsense_dists]

print(f"  Factual coverage radius R: {R_factual:.3f}")
print(f"  Nonsense distances from factual cluster:")
for i, (d, c) in enumerate(zip(nonsense_dists, confidences)):
    in_horizon = d <= 2.362 * R_factual  # instinct horizon with N=7
    print(f"    \"{nonsense_prompts[i][:40]}...\"")
    print(f"      d={d:.3f}, c={c:.4f}, in_horizon={in_horizon}")

# Falsifiable prediction: do hallucinations cluster in low-density regions?
avg_nonsense_dist = np.mean(nonsense_dists)
avg_factual_nn = R_factual
tear_ratio = avg_nonsense_dist / max(avg_factual_nn, 1e-10)

print(f"\n  Avg factual NN distance: {avg_factual_nn:.3f}")
print(f"  Avg nonsense distance:   {avg_nonsense_dist:.3f}")
print(f"  Tear ratio:              {tear_ratio:.2f}x")
print(f"  → Nonsense is {tear_ratio:.1f}x farther from knowledge than facts are from each other")

# Auto-detect hallucinations
n_detected = sum(1 for c in confidences if c < 0.1)  # below 10% confidence
print(f"  Auto-detected hallucinations: {n_detected}/{len(nonsense_prompts)}")
print(f"  Detection rate: {n_detected/len(nonsense_prompts)*100:.0f}%")

verdict_4 = "CONFIRMED" if tear_ratio > 2.0 else "MARGINAL"

results["tests"]["topological_tears"] = {
    "coverage_radius_R": round(R_factual, 4),
    "avg_nonsense_distance": round(avg_nonsense_dist, 4),
    "tear_ratio": round(tear_ratio, 2),
    "hallucinations_detected": f"{n_detected}/{len(nonsense_prompts)}",
    "detection_rate_pct": round(n_detected / len(nonsense_prompts) * 100, 1),
    "individual_distances": [round(d, 3) for d in nonsense_dists],
    "individual_confidences": [round(c, 4) for c in confidences],
    "verdict": verdict_4,
}

# 
# TEST 5: TOPOLOGICAL COMPRESSION — Chain Jacobi Propagators
# 
print("\n" + "=" * 70)
print("TEST 5: Topological Compression — Chain Jacobi Propagators")
print("=" * 70)

# Simulate: encode a sequence of hidden states as chained propagators
# This mimics compressing conversation context into geometric summaries

seq_len = 12
k_comp = 16
np.random.seed(42)

# Generate a "conversation" as a trajectory through k-space
trajectory = torch.zeros(seq_len, k_comp)
trajectory[0] = torch.randn(k_comp) * 0.3
for i in range(1, seq_len):
    # Drift + small random step
    trajectory[i] = trajectory[i-1] + torch.randn(k_comp) * 0.2

# Method A: Store every point (full context)
full_storage_bytes = seq_len * k_comp * 4  # float32

# Method B: Chain Jacobi propagators (compressed)
# For each segment of 3 points, compute the Jacobi propagator
segment_size = 3
n_segments = seq_len // segment_size
propagators = []
waypoints = []
errors = []

for seg in range(n_segments):
    start = seg * segment_size
    pts = trajectory[start:start + segment_size]
    waypoints.append(pts[0])
    
    # Jacobi propagator: how does deviation at step 0 affect step 2?
    # Simplified: linear fit between start and end of segment
    delta = pts[-1] - pts[0]
    # Rank-1 propagator: direction from start to end
    if delta.norm() > 1e-10:
        phi = torch.outer(delta, pts[1] - pts[0]) / (delta.norm() ** 2 + 1e-10)
    else:
        phi = torch.eye(k_comp)
    propagators.append(phi)
    
    # Reconstruction error
    reconstructed = pts[0] + phi @ (pts[1] - pts[0])
    error = (reconstructed - pts[-1]).norm().item()
    errors.append(error)

compressed_bytes = n_segments * (k_comp * 4 + k_comp * k_comp * 4)  # waypoints + propagators
compression_ratio = full_storage_bytes / max(compressed_bytes, 1e-10)
avg_error = np.mean(errors)

print(f"  Full context storage:    {full_storage_bytes} bytes")
print(f"  Compressed storage:      {compressed_bytes} bytes")
print(f"  Compression ratio:       {compression_ratio:.2f}x")
print(f"  Avg reconstruction error: {avg_error:.4f} per segment")
print(f"  Propagators stored:      {n_segments} (rank-1 each)")

# Chain: can we reconstruct the full trajectory from propagators?
reconstructed_traj = torch.zeros_like(trajectory)
reconstructed_traj[0] = trajectory[0]
for seg in range(n_segments):
    start = seg * segment_size
    pts = trajectory[start:start + segment_size]
    # Use stored propagator
    reconstructed_traj[start + 2] = pts[0] + propagators[seg] @ (pts[1] - pts[0])
    reconstructed_traj[start + 1] = pts[1]  # store intermediate

total_reconstruction_error = (reconstructed_traj - trajectory).norm().item()
rel_error = total_reconstruction_error / max(trajectory.norm().item(), 1e-10)

print(f"  Total reconstruction error: {total_reconstruction_error:.4f}")
print(f"  Relative error:             {rel_error*100:.2f}%")

verdict_5 = "CONFIRMED" if compression_ratio > 1.5 and rel_error < 0.5 else "FEASIBLE"

results["tests"]["topological_compression"] = {
    "full_storage_bytes": full_storage_bytes,
    "compressed_storage_bytes": compressed_bytes,
    "compression_ratio": round(compression_ratio, 2),
    "avg_reconstruction_error": round(avg_error, 4),
    "total_reconstruction_error": round(total_reconstruction_error, 4),
    "relative_error_pct": round(rel_error * 100, 2),
    "n_segments": n_segments,
    "segment_size": segment_size,
    "verdict": verdict_5,
}

# 
# SUMMARY
# 
print("\n" + "=" * 70)
print("FIVE PRINCIPLES — RESULTS")
print("=" * 70)

for name, test in results["tests"].items():
    verdict = test.get("verdict", "?")
    symbol = "" if "CONFIRM" in str(verdict) else ""
    print(f"  {symbol} {name}: {verdict}")

n_confirmed = sum(1 for t in results["tests"].values() if "CONFIRM" in str(t.get("verdict", "")))
print(f"\n  Confirmed: {n_confirmed}/{len(results['tests'])}")

# Save
out_path = OUT_DIR / 'results.json'
with open(out_path, 'w') as f:
    json.dump(results, f, indent=2)

# Cleanup
del model
torch.cuda.empty_cache()

print(f"\nResults: {out_path}")
print("=" * 70)
