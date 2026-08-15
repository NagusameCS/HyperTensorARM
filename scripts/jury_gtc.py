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


"""JURY-GTC — Jury-Accelerated Geodesic Trajectory Caching.

GTC (Paper IV/VIII) caches trajectories and serves queries via nearest-neighbor
lookup. Naive GTC is O(N) per query. The jury provides domain knowledge that
enables O(log N) or O(sqrt N) search.

ACCELERATION STRATEGIES:
  1. Domain Pre-Routing: Use contrastive jury on a random SAMPLE of trajectories
     to identify the dominant domain, then fine-search only that domain's cache.
  2. Importance-Ordered Search: Check high-value trajectories first. Stop early
     if similarity exceeds threshold.
  3. Overlap-Based Pruning: Skip entire domains whose overlap with the query
     domain falls below threshold.
  4. Two-Stage Rocket: Stage 1 = softmax on 20 random trajectories → identify
     top-2 domains. Stage 2 = linear search only those domains' caches.
  5. Adaptive Threshold: Use per-domain coverage radius R to set similarity
     threshold. Tight clusters need higher sim; loose clusters accept lower.

METRICS:
  - Comparisons saved vs naive O(N)
  - Hit rate: does accelerated search find the same best match?
  - Effective speedup factor
  - Jury overhead vs benefit
"""
import torch, json, time, math, random, os
from pathlib import Path
from collections import defaultdict
import torch.nn.functional as F

torch.set_grad_enabled(False)
torch.manual_seed(42)
random.seed(42)

print("=" * 70)
print("  JURY-GTC — Accelerating Trajectory Cache with Jury Routing")
print("  Can domain knowledge from the jury speed up GTC?")
print("=" * 70)

# ============================================================================
# LOAD SAIYANS + BUILD LARGE TRAJECTORY POOL
# ============================================================================
STATE_DIR = Path("outputs/saiyan_states")
if not STATE_DIR.exists():
    STATE_DIR = Path("/home/ubuntu/outputs/saiyan_states")

DOMAINS = {
    "Goku": "math", "Vegeta": "code", "Gohan": "science",
    "Piccolo": "logic", "Trunks": "creative", "Yamcha": "general",
}

# Domain overlap matrix (from jury_discovery.py for pruning)
OVERLAP = {
    ("Goku","Yamcha"): 0.930, ("Goku","Trunks"): 0.932, ("Goku","Vegeta"): 0.990,
    ("Goku","Gohan"): 0.972, ("Goku","Piccolo"): 0.988,
    ("Vegeta","Yamcha"): 0.960, ("Vegeta","Trunks"): 0.961, ("Vegeta","Gohan"): 0.985,
    ("Vegeta","Piccolo"): 0.996,
    ("Gohan","Yamcha"): 0.983, ("Gohan","Trunks"): 0.984, ("Gohan","Piccolo"): 0.994,
    ("Piccolo","Yamcha"): 0.975, ("Piccolo","Trunks"): 0.976,
    ("Trunks","Yamcha"): 1.000,
}

def get_overlap(d1, d2):
    if d1 == d2: return 1.0
    key = tuple(sorted([d1, d2]))
    return OVERLAP.get(key, 0.95)

# Asymmetric transfer hints (from jury_discovery.py)
# Higher number = better transfer from src to dst
TRANSFER_HINTS = {
    ("Vegeta","Goku"): 0.629,  # code→math transfers well
    ("Piccolo","Vegeta"): 0.846,  # logic→code transfers very well
    ("Piccolo","Goku"): 0.744,  # logic→math
    ("Gohan","Piccolo"): 0.766,  # science→logic
}

def get_transfer_hint(src, dst):
    return TRANSFER_HINTS.get((src, dst), 0.5)

# Load and augment Saiyan trajectories
saiyans = {}
for pt_file in sorted(STATE_DIR.glob("*_saiyan.pt")):
    name = pt_file.stem.replace("_saiyan", "")
    if name not in DOMAINS: continue
    data = torch.load(pt_file, map_location="cpu")
    trajs = []
    for t in data.get("trajectories", []):
        if isinstance(t, dict) and "proj" in t:
            trajs.append({"proj": t["proj"].float(), "parent": name, "domain": DOMAINS[name], "importance": 1.0})
    # Augment to ~50
    R = 0.02
    while len(trajs) < 50:
        i, j = random.sample(range(len(trajs)), 2)
        a = random.random()
        n = torch.randn_like(trajs[0]["proj"]) * R * 0.5
        m = F.normalize((trajs[i]["proj"]*a + trajs[j]["proj"]*(1-a) + n).unsqueeze(0), dim=1).squeeze(0)
        trajs.append({"proj": m, "parent": name, "domain": DOMAINS[name], "importance": 0.5})
    saiyans[name] = trajs
    print(f"  {name:12s}: {len(trajs)} trajectories")

# Build unified trajectory pool
all_trajs = []
for name, trajs in saiyans.items():
    for t in trajs:
        all_trajs.append(dict(t))
print(f"\n  Total pool: {len(all_trajs)} trajectories")

# Pre-compute normalized embeddings for fast search
all_projs = F.normalize(torch.stack([t["proj"] for t in all_trajs]), dim=1)
domain_indices = defaultdict(list)
for i, t in enumerate(all_trajs):
    domain_indices[t["parent"]].append(i)

# Coverage radii per domain
coverage_R = {}
for name in saiyans:
    projs = F.normalize(torch.stack([t["proj"] for t in saiyans[name]]), dim=1)
    sims = projs @ projs.T
    n = len(saiyans[name])
    idx = torch.triu_indices(n, n, offset=1)
    coverage_R[name] = max(0.01, (1 - sims[idx[0], idx[1]]).median().item())

# ============================================================================
# GTC SEARCH METHODS
# ============================================================================

def naive_gtc_search(q, threshold=0.95):
    """O(N) linear search. Baseline."""
    qn = F.normalize(q.unsqueeze(0), dim=1)
    sims = (all_projs @ qn.T).squeeze(-1)
    best_idx = torch.argmax(sims).item()
    best_sim = sims[best_idx].item()
    comparisons = len(all_trajs)
    hit = best_sim >= threshold
    return {"best_idx": best_idx, "best_sim": best_sim, "hit": hit, 
            "comparisons": comparisons, "best_domain": all_trajs[best_idx]["parent"]}

def jury_two_stage_search(q, threshold=0.95, sample_size=20):
    """Stage 1: softmax on random sample → find dominant domain.
       Stage 2: linear search only that domain + top-2 transfer domains."""
    qn = F.normalize(q.unsqueeze(0), dim=1)
    
    # Stage 1: Sample random trajectories and run jury
    sample_indices = random.sample(range(len(all_trajs)), min(sample_size, len(all_trajs)))
    sample_projs = all_projs[sample_indices]
    sims_sample = (sample_projs @ qn.T).squeeze(-1)
    w = F.softmax(sims_sample * 8.0, dim=0)
    
    # Find dominant domain from sample
    domain_weights = defaultdict(float)
    for si, idx in enumerate(sample_indices):
        domain_weights[all_trajs[idx]["parent"]] += w[si].item()
    
    # Top-2 domains
    sorted_domains = sorted(domain_weights, key=domain_weights.get, reverse=True)
    search_domains = sorted_domains[:2]
    
    # Stage 2: Fine-search only those domains
    stage1_comparisons = sample_size
    
    best_sim = -1
    best_idx = -1
    stage2_comparisons = 0
    
    for domain in search_domains:
        for idx in domain_indices[domain]:
            stage2_comparisons += 1
            sim = F.cosine_similarity(qn, all_projs[idx].unsqueeze(0)).item()
            if sim > best_sim:
                best_sim = sim
                best_idx = idx
                if best_sim >= 0.99:  # early termination
                    break
    
    total_comparisons = stage1_comparisons + stage2_comparisons
    hit = best_sim >= threshold
    
    return {"best_idx": best_idx, "best_sim": best_sim, "hit": hit,
            "comparisons": total_comparisons, "best_domain": all_trajs[best_idx]["parent"],
            "stage1_domains": search_domains}

def jury_pruned_search(q, threshold=0.95, overlap_cutoff=0.97):
    """Prune domains with high overlap (redundant). Search only distinct ones."""
    qn = F.normalize(q.unsqueeze(0), dim=1)
    
    # First, find which domain the query most likely belongs to
    # Use a quick 10-sample jury
    sample_indices = random.sample(range(len(all_trajs)), 10)
    sample_projs = all_projs[sample_indices]
    sims_sample = (sample_projs @ qn.T).squeeze(-1)
    best_sample_idx = sample_indices[torch.argmax(sims_sample).item()]
    likely_domain = all_trajs[best_sample_idx]["parent"]
    
    # Search all domains except those with overlap > cutoff to likely_domain
    # (they're redundant — same info, different label)
    skipped = 0
    searched = 0
    best_sim = -1
    best_idx = -1
    
    for domain in saiyans:
        ol = get_overlap(likely_domain, domain)
        if ol > overlap_cutoff and domain != likely_domain:
            skipped += len(domain_indices[domain])
            continue
        for idx in domain_indices[domain]:
            searched += 1
            sim = F.cosine_similarity(qn, all_projs[idx].unsqueeze(0)).item()
            if sim > best_sim:
                best_sim = sim
                best_idx = idx
    
    total = 10 + searched + skipped
    hit = best_sim >= threshold
    return {"best_idx": best_idx, "best_sim": best_sim, "hit": hit,
            "comparisons": 10 + searched, "skipped": skipped,
            "total_pool": len(all_trajs), "best_domain": all_trajs[best_idx]["parent"]}

def jury_importance_ordered_search(q, threshold=0.95):
    """Search high-importance trajectories first. Stop early on hit."""
    qn = F.normalize(q.unsqueeze(0), dim=1)
    
    # Sort trajectories by importance (pre-computed from jury_discovery.py)
    # For now, use coverage radius as proxy: smaller R = more specialized = higher importance
    sorted_indices = sorted(range(len(all_trajs)), 
                           key=lambda i: -all_trajs[i].get("importance", 0.5))
    
    best_sim = -1
    best_idx = -1
    comparisons = 0
    for idx in sorted_indices:
        comparisons += 1
        sim = F.cosine_similarity(qn, all_projs[idx].unsqueeze(0)).item()
        if sim > best_sim:
            best_sim = sim
            best_idx = idx
            if best_sim >= threshold:
                break  # early termination
    
    hit = best_sim >= threshold
    return {"best_idx": best_idx, "best_sim": best_sim, "hit": hit,
            "comparisons": comparisons, "best_domain": all_trajs[best_idx]["parent"]}

def jury_adaptive_threshold_search(q, likely_domain=None):
    """Use per-domain coverage radius as adaptive threshold."""
    qn = F.normalize(q.unsqueeze(0), dim=1)
    
    # Quick domain detection
    if likely_domain is None:
        sample = random.sample(range(len(all_trajs)), 10)
        sp = all_projs[sample]
        ss = (sp @ qn.T).squeeze(-1)
        likely_domain = all_trajs[sample[torch.argmax(ss).item()]]["parent"]
    
    # Adaptive threshold: R-based
    R = coverage_R.get(likely_domain, 0.02)
    adaptive_threshold = 1.0 - R * 2.0  # within 2 coverage radii
    
    # Search likely domain first
    best_sim = -1
    best_idx = -1
    comparisons = 0
    for idx in domain_indices[likely_domain]:
        comparisons += 1
        sim = F.cosine_similarity(qn, all_projs[idx].unsqueeze(0)).item()
        if sim > best_sim:
            best_sim = sim
            best_idx = idx
    
    hit = best_sim >= adaptive_threshold
    return {"best_idx": best_idx, "best_sim": best_sim, "hit": hit,
            "comparisons": 10 + comparisons, "threshold": adaptive_threshold,
            "domain_R": R, "best_domain": likely_domain}

# ============================================================================
# BENCHMARK ALL METHODS
# ============================================================================
print(f"\n{'='*70}")
print("  BENCHMARK: 200 queries, 5 search methods")
print(f"{'='*70}")

# Generate test queries from all domains
test_queries = []
for name in saiyans:
    for i in range(min(8, len(saiyans[name]))):
        q = saiyans[name][i]["proj"].clone()
        q = F.normalize((q + torch.randn_like(q)*0.03).unsqueeze(0), dim=1).squeeze(0)
        test_queries.append({"feat": q, "domain": name})

# Skip if too many to be fast
if len(test_queries) > 48:
    test_queries = random.sample(test_queries, 48)

print(f"  Testing {len(test_queries)} queries across {len(all_trajs)} trajectories...")

methods = {
    "Naive O(N)": naive_gtc_search,
    "Two-Stage Jury": jury_two_stage_search,
    "Overlap-Pruned": jury_pruned_search,
    "Importance-Ordered": jury_importance_ordered_search,
    "Adaptive Threshold": jury_adaptive_threshold_search,
}

results = {name: {"comparisons": [], "hits": 0, "best_match": 0, "time_ms": []} for name in methods}

for qi, tq in enumerate(test_queries):
    q = tq["feat"]
    true_domain = tq["domain"]
    
    # Naive baseline first (ground truth best match)
    naive_result = naive_gtc_search(q)
    gt_best_idx = naive_result["best_idx"]
    
    for method_name, method_fn in methods.items():
        t0 = time.perf_counter()
        result = method_fn(q)
        elapsed = (time.perf_counter() - t0) * 1000
        
        results[method_name]["comparisons"].append(result["comparisons"])
        results[method_name]["time_ms"].append(elapsed)
        if result["hit"]:
            results[method_name]["hits"] += 1
        if result["best_idx"] == gt_best_idx:
            results[method_name]["best_match"] += 1

# Print results
print(f"\n  {'Method':22s} {'Comps':>8s} {'Saved':>8s} {'Time':>8s} {'Hit%':>7s} {'Match%':>7s}")
print(f"  {'-'*22} {'-'*8} {'-'*8} {'-'*8} {'-'*7} {'-'*7}")

naive_comps = sum(results["Naive O(N)"]["comparisons"]) / len(results["Naive O(N)"]["comparisons"])
naive_time = sum(results["Naive O(N)"]["time_ms"]) / len(results["Naive O(N)"]["time_ms"])

for method_name in methods:
    r = results[method_name]
    avg_comps = sum(r["comparisons"]) / len(r["comparisons"])
    avg_time = sum(r["time_ms"]) / len(r["time_ms"])
    saved = (1 - avg_comps / naive_comps) * 100
    hit_pct = r["hits"] / len(test_queries) * 100
    match_pct = r["best_match"] / len(test_queries) * 100
    
    speedup = naive_time / max(avg_time, 0.001)
    marker = "" if saved > 20 else " "
    print(f"  {method_name:22s} {avg_comps:>7.0f} {saved:>7.0f}% {avg_time:>7.2f}ms {hit_pct:>6.1f}% {match_pct:>6.1f}% {marker}")

# ============================================================================
# DETAILED ANALYSIS
# ============================================================================
print(f"\n{'='*70}")
print("  DETAILED ANALYSIS")
print(f"{'='*70}")

# Best method by comparisons saved
best_method = max(methods, key=lambda m: (1 - sum(results[m]["comparisons"])/max(sum(results["Naive O(N)"]["comparisons"]),1)))
best_saved = (1 - sum(results[best_method]["comparisons"])/max(sum(results["Naive O(N)"]["comparisons"]),1)) * 100

# Best method by match accuracy
best_match_method = max(methods, key=lambda m: results[m]["best_match"])
best_match_pct = results[best_match_method]["best_match"] / len(test_queries) * 100

print(f"\n  Best comparison savings: {best_method} ({best_saved:.0f}% saved)")
print(f"  Best match accuracy:     {best_match_method} ({best_match_pct:.0f}%)")

# Domain-specific analysis
print(f"\n  PER-DOMAIN TWO-STAGE JURY PERFORMANCE:")
domain_perf = defaultdict(lambda: {"saved": [], "match": 0, "total": 0})
for qi, tq in enumerate(test_queries):
    d = tq["domain"]
    r = results["Two-Stage Jury"]
    saved = (1 - r["comparisons"][qi] / naive_comps) * 100
    domain_perf[d]["saved"].append(saved)
    domain_perf[d]["total"] += 1
    if r["best_match"]: domain_perf[d]["match"] += 1

for d in sorted(domain_perf):
    dp = domain_perf[d]
    avg_saved = sum(dp["saved"]) / len(dp["saved"])
    match_pct = dp["match"] / dp["total"] * 100
    print(f"    {d:12s}: {avg_saved:.0f}% saved, {match_pct:.0f}% match ({dp['match']}/{dp['total']})")

# ============================================================================
# IMPLEMENTATION RECOMMENDATIONS
# ============================================================================
print(f"\n{'='*70}")
print("  IMPLEMENTATION RECOMMENDATIONS")
print(f"{'='*70}")

print(f"""
  Based on benchmark results, the jury can accelerate GTC by:

  1. TWO-STAGE ROCKET (best for large caches):
     Stage 1: Jury softmax on 20 random trajectories → dominant domain
     Stage 2: Linear search only that domain + 1 transfer domain
     Savings: ~{best_saved:.0f}% of comparisons vs naive O(N)
     Use when: pool > 200 trajectories

  2. PER-DOMAIN ADAPTIVE THRESHOLDS:
     Use coverage radius R to set domain-specific similarity thresholds.
     Tight clusters (math: R={coverage_R.get('Goku',0):.3f}) need higher sim.
     Loose clusters (general: R={coverage_R.get('Yamcha',0):.3f}) accept lower.
     Use when: mixed-domain trajectory pools

  3. OVERLAP-BASED PRUNING:
     When domain overlap > 0.99, the domains are redundant.
     Skip searching the redundant one entirely.
     Example: Trunks↔Yamcha overlap = 1.000 — skip one!
     Use when: known domain topology available

  4. IMPORTANCE-ORDERED EARLY EXIT:
     Check high-importance trajectories first.
     Exit early when similarity exceeds threshold.
     Use when: trajectory importance scores are pre-computed

  JURY-GTC INTEGRATION:
    The jury doesn't replace GTC — it ACCELERATES it.
    For ISAGI v1.1, add two-stage routing before cache lookup.
    Expected speedup: {naive_time/max(sum(results['Two-Stage Jury']['time_ms'])/len(results['Two-Stage Jury']['time_ms']), 0.001):.1f}x for 300+ trajectory pools.
""")

# Save results
os.makedirs("benchmarks/jury_gtc", exist_ok=True)
with open("benchmarks/jury_gtc/results.json", "w") as f:
    json.dump({
        "timestamp": time.strftime("%Y-%m-%d %H:%M:%S"),
        "pool_size": len(all_trajs),
        "n_queries": len(test_queries),
        "naive_comps_avg": naive_comps,
        "methods": {
            name: {
                "avg_comparisons": sum(r["comparisons"])/len(r["comparisons"]),
                "avg_time_ms": sum(r["time_ms"])/len(r["time_ms"]),
                "hit_rate": r["hits"]/len(test_queries),
                "match_rate": r["best_match"]/len(test_queries),
                "savings_pct": (1 - sum(r["comparisons"])/max(sum(results["Naive O(N)"]["comparisons"]),1))*100,
            } for name, r in results.items()
        },
        "domain_coverage_R": coverage_R,
    }, f, indent=2)

print(f"  Results saved to benchmarks/jury_gtc/results.json")
