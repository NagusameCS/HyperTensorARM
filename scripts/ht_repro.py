#!/usr/bin/env python3
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
#  ::::::::::::::::::::::.......................+@@@-......................:::::::::::::::::::::
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
#  :::::::::::::::...........:#@@@@@@@@@@@#--+%@@@@@@@#=:=%@@@@@@@@@@-............:::::::::::::::
#  ::::::::::::::::............-@@@@@@+-=#@@@@@@@@@@@@@@@@#=-=#@@@@*:............:::::::::::::::
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

"""
ht-repro — HyperTensor Reproduction CLI
========================================

One command to reproduce any paper, or all papers, in the HyperTensor extended volume.

Usage:
  ht-repro smoke              # 60-second smoke test (Papers XVI-XVIII core math)
  ht-repro all-t1             # All CPU-only tests (~30 min)
  ht-repro paper-1            # Reproduce Paper I (GRC)
  ht-repro jury               # All jury verification scripts
  ht-repro riemann            # All Riemann Hypothesis verification
  ht-repro list               # List all available tests
  ht-repro status             # Show last run results
  ht-repro summary            # Print a summary of all verified results

Based on the HyperTensor Geometric Jury framework (Papers I–XVIII).
"""

import argparse
import json
import os
import subprocess
import sys
import time
from pathlib import Path
from datetime import datetime
from typing import Dict, List, Optional, Tuple

# ── Paths ──────────────────────────────────────────────────────────
ROOT = Path(__file__).resolve().parent.parent
SCRIPTS = ROOT / "scripts"
BENCHMARKS = ROOT / "benchmarks"
RESULTS_FILE = BENCHMARKS / "ht_repro_results.json"
EXPECTED_FILE = BENCHMARKS / "ht_repro_expected.json"

# ── Test Catalog ───────────────────────────────────────────────────
# Each entry: (id, name, script, tier, expected_output, paper, timeout_s)
CATALOG: List[dict] = [
    # ── Core (T1, CPU-only) ──
    {"id":"smoke","name":"60-Second Smoke Test (Riemann core math)","script":"scripts/faithfulness_rigorous.py","tier":"T1","paper":"XVI-XVIII","expected":"SV1=8.944272, SV2..SV12=0.000000","timeout":60,"group":"core"},
    {"id":"jury-proof","name":"Jury Proof (8 Theorems)","script":"scripts/jury_final.py","tier":"T1","paper":"Foundation","expected":"8 theorems verified, J = 1−∏(1−cᵢ)","timeout":30,"group":"jury"},
    {"id":"jury-horizon","name":"Jury Horizon + J-Decay","script":"scripts/jury_horizon.py","tier":"T1","paper":"Foundation","expected":"J-decay table, d_h derived","timeout":30,"group":"jury"},
    {"id":"jury-scaling","name":"Jury Scaling (174× speedup)","script":"scripts/jury_scaling.py","tier":"T1","paper":"Foundation","expected":"174× at 128 jurors","timeout":30,"group":"jury"},
    {"id":"jury-ensemble","name":"Jury Ensemble (Regression vs Classification)","script":"scripts/jury_ensemble.py","tier":"T1","paper":"Foundation","expected":"Regression beats classification","timeout":30,"group":"jury"},
    {"id":"riemann-lmfdb","name":"Riemann LMFDB Meta-Jury (54,949 zeros)","script":"scripts/validate_riemann_lmfdb.py","tier":"T1","paper":"XVIII","expected":"100% on critical, TPR=1.0, FPR=0.0","timeout":120,"group":"riemann"},
    {"id":"riemann-agt","name":"AGT v3 — Zeta Zero Topology","script":"scripts/agt_v3.py","tier":"T1","paper":"XVI","expected":"98% detection, 1392× separation, k90=k95=1","timeout":120,"group":"riemann"},
    {"id":"riemann-comprehensive","name":"Riemann Comprehensive Verify (9 tests)","script":"scripts/riemann_comprehensive_verify.py","tier":"T1","paper":"XVI-XVIII","expected":"ALL 9 TESTS PASSED","timeout":120,"group":"riemann"},
    {"id":"safe-ogd","name":"Safe OGD — Zero Forbidden Leakage","script":"scripts/verify_safe_loss_aczel.py","tier":"T1","paper":"XIII","expected":"0% forbidden leakage","timeout":30,"group":"safety"},
    {"id":"gtc-vs-rag","name":"GTC vs RAG Benchmark","script":"scripts/gtc_vs_rag.py","tier":"T1","paper":"VIII","expected":"30.9 µs/q, 5.96 KB/record","timeout":60,"group":"runtime"},
    {"id":"bp-ns-bound","name":"BP/NS Bound Verification","script":"scripts/verify_bp_ns_bound.py","tier":"T1","paper":"Audit","expected":"160/160 trials pass","timeout":30,"group":"audit"},
    {"id":"behavioral-residue","name":"Behavioral Residue Invariant","script":"scripts/verify_behavioral_residue_invariant.py","tier":"T1","paper":"Audit","expected":"Layers 0-22 hold, layer 29 may fail","timeout":120,"group":"audit"},

    # ── GPU-dependent (T2) ──
    {"id":"bilateral-ugt","name":"Bilateral UGT (Subspace Overlap)","script":"scripts/bilateral_ugt.py","tier":"T2","paper":"XI","expected":"overlap > 0.99","timeout":600,"group":"living"},
    {"id":"acm-prototype","name":"ACM Prototype — Learned Involution","script":"scripts/acm_prototype.py","tier":"T2","paper":"XVII","expected":"ι²≈id (ε=0.009)","timeout":120,"group":"riemann"},
    {"id":"grc-distill","name":"GRC Light Distillation (Phase 1)","script":"scripts/grc_distill.py --phase1-only","tier":"T2","paper":"V","expected":"ρ ratio computed","timeout":120,"group":"compression"},

    # ── Full-scale (T3) ──
    {"id":"agt-scale","name":"AGT at 50K Primes (Full Scale)","script":"scripts/agt_scale_ec2.py","tier":"T3","paper":"XVI","expected":"100% detection, 800× separation","timeout":1800,"group":"riemann"},
    {"id":"cog-10k","name":"COG 10K Interaction Test","script":"scripts/cog_10k.py","tier":"T3","paper":"XV","expected":"COG converged, zero novel in final 7000","timeout":3600,"group":"living"},
]

# ── Expected Outputs Database ──────────────────────────────────────
EXPECTED_OUTPUTS = {
    "smoke": {
        "sv1": 8.944272, "sv2_12_zero": True,
        "z2_exact": True, "error_at_k12": 0.0,
    },
    "jury-proof": {"theorems_verified": 8, "jury_formula": "J = 1 - Prod(1 - c_i)"},
    "jury-horizon": {"j_decay_table": True, "d_h_derived": True},
    "jury-scaling": {"speedup_128_jurors": "~174x", "speedup_512_jurors": "~153x"},
    "jury-ensemble": {"regression_better": True, "ceci_mae": "< 0.12"},
    "riemann-lmfdb": {"on_critical_pct": 100.0, "tpr": 1.0, "fpr": 0.0},
    "riemann-agt": {"detection_rate": "≥98%", "k90": 1, "k95": 1},
    "riemann-comprehensive": {"all_tests_pass": True},
    "safe-ogd": {"arithmetic_mean": True, "max_loss_dro": True, "forbidden_leakage": 0.0},
    "gtc-vs-rag": {"lookup_us": "~30.9", "record_kb": "~5.96"},
    "bp-ns-bound": {"trials_pass": 160, "total": 160},
    "behavioral-residue": {"layers_0_22_hold": True, "layer_29_note": "ratio=0.79, investigation needed"},
}

# ── Color Helpers ──────────────────────────────────────────────────
GREEN = "\033[92m"; RED = "\033[91m"; YELLOW = "\033[93m"
BLUE = "\033[94m"; BOLD = "\033[1m"; RESET = "\033[0m"

def green(s): return f"{GREEN}{s}{RESET}"
def red(s): return f"{RED}{s}{RESET}"
def yellow(s): return f"{YELLOW}{s}{RESET}"
def blue(s): return f"{BLUE}{s}{RESET}"
def bold(s): return f"{BOLD}{s}{RESET}"

# ── Core Functions ─────────────────────────────────────────────────

def find_test(test_id: str) -> Optional[dict]:
    """Find a test by its ID."""
    for t in CATALOG:
        if t["id"] == test_id:
            return t
    return None

def run_test(test: dict, verbose: bool = False) -> Tuple[bool, str, float]:
    """
    Run a single test script. Returns (passed, output_summary, elapsed_seconds).
    """
    script_path = ROOT / test["script"]
    if not script_path.exists():
        return False, f"Script not found: {script_path}", 0.0

    t0 = time.time()
    env = os.environ.copy()
    env["PYTHONPATH"] = str(ROOT)

    try:
        result = subprocess.run(
            [sys.executable, str(script_path)],
            cwd=str(ROOT),
            env=env,
            capture_output=True,
            text=True,
            timeout=test["timeout"],
        )
        elapsed = time.time() - t0
        output = result.stdout + result.stderr

        if verbose:
            print(output[-2000:])  # last 2000 chars

        # Check for expected output patterns
        expected = test.get("expected", "")
        passed = expected.lower() in output.lower() if expected else result.returncode == 0

        # Extract a short summary from the last few lines
        lines = [l.strip() for l in output.split("\n") if l.strip()]
        summary = "\n".join(lines[-5:]) if lines else "(no output)"

        return passed, summary, elapsed

    except subprocess.TimeoutExpired:
        elapsed = time.time() - t0
        return False, f"TIMEOUT after {test['timeout']}s", elapsed
    except Exception as e:
        elapsed = time.time() - t0
        return False, str(e), elapsed

def load_results() -> dict:
    """Load previous run results."""
    if RESULTS_FILE.exists():
        with open(RESULTS_FILE) as f:
            return json.load(f)
    return {"runs": []}

def save_results(results: dict):
    """Save run results to JSON."""
    BENCHMARKS.mkdir(exist_ok=True)
    with open(RESULTS_FILE, "w") as f:
        json.dump(results, f, indent=2)

def check_expected(test_id: str, output: str) -> dict:
    """Compare test output against expected values."""
    exp = EXPECTED_OUTPUTS.get(test_id, {})
    matches = {}
    for key, expected_val in exp.items():
        if isinstance(expected_val, bool):
            # Check for boolean indicators in output
            indicator = "true" if expected_val else "false"
            matches[key] = indicator in output.lower()
        elif isinstance(expected_val, (int, float)):
            matches[key] = str(expected_val) in output
        elif isinstance(expected_val, str):
            matches[key] = expected_val.lower() in output.lower()
    return matches

# ── CLI Commands ───────────────────────────────────────────────────

def cmd_smoke():
    """Run the 60-second smoke test."""
    test = find_test("smoke")
    if not test:
        print(red("Smoke test not found in catalog!"))
        return

    print(bold(blue("\n═══ HyperTensor 60-Second Smoke Test ═══\n")))
    passed, output, elapsed = run_test(test, verbose=True)

    if passed:
        print(green("\n SMOKE TEST PASSED"))
        print("   SV1=8.944272, SV2..SV12=0.000000, Z₂ symmetry EXACT")
    else:
        print(red("\n SMOKE TEST FAILED"))
        print(f"   {output[-500:]}")

    print(f"   Time: {elapsed:.1f}s\n")

def cmd_all_t1():
    """Run all T1 (CPU-only) tests."""
    t1_tests = [t for t in CATALOG if t["tier"] == "T1"]
    _run_batch("All T1 (CPU-Only) Tests", t1_tests)

def cmd_paper(paper_id: int):
    """Run tests for a specific paper."""
    paper_map = {
        1: "I", 2: "II", 3: "III", 4: "IV", 5: "V", 6: "VI",
        7: "VII", 8: "VIII", 9: "IX", 10: "X",
        11: "XI", 12: "XII", 13: "XIII", 14: "XIV", 15: "XV",
        16: "XVI", 17: "XVII", 18: "XVIII",
    }
    paper_label = paper_map.get(paper_id, str(paper_id))
    tests = [t for t in CATALOG if t["paper"] in [paper_label, f"{paper_label}-", "Foundation" if paper_id == 0 else ""]]
    # Also include papers that mention this paper in their paper field
    tests = [t for t in CATALOG if paper_label in t["paper"] or (paper_id == 0 and "Foundation" in t["paper"])]

    if not tests:
        print(yellow(f"No tests found for Paper {paper_label} (paper {paper_id})."))
        print("Available papers with tests:", sorted(set(t["paper"] for t in CATALOG if t["tier"] == "T1")))
        return

    _run_batch(f"Paper {paper_label} Tests", tests)

def cmd_group(group: str):
    """Run tests by group (jury, riemann, safety, runtime, audit, compression, living, core)."""
    tests = [t for t in CATALOG if t["group"] == group]
    if not tests:
        print(yellow(f"No tests found for group '{group}'."))
        print("Available groups:", sorted(set(t["group"] for t in CATALOG)))
        return
    _run_batch(f"Group: {group}", tests)

def _run_batch(title: str, tests: List[dict]):
    """Run a batch of tests with progress tracking."""
    print(bold(blue(f"\n═══ {title} ({len(tests)} tests) ═══\n")))

    results_data = load_results()
    run_record = {
        "timestamp": datetime.now().isoformat(),
        "tests": {},
        "passed": 0,
        "failed": 0,
        "skipped": 0,
        "total_time": 0.0,
    }

    for i, test in enumerate(tests):
        tier_label = {"T1": green("T1"), "T2": yellow("T2"), "T3": red("T3")}.get(test["tier"], test["tier"])
        print(f"[{i+1}/{len(tests)}] {tier_label} {test['name']}...", end=" ", flush=True)

        # Check if we can run this tier
        if test["tier"] == "T2":
            try:
                import torch
                has_gpu = torch.cuda.is_available()
            except ImportError:
                has_gpu = False
            if not has_gpu:
                print(yellow("SKIP (needs GPU)"))
                run_record["skipped"] += 1
                run_record["tests"][test["id"]] = {"status": "skipped", "reason": "Needs GPU"}
                continue

        if test["tier"] == "T3":
            print(yellow("SKIP (T3 datacenter GPU needed — use pre-computed reference)"))
            run_record["skipped"] += 1
            run_record["tests"][test["id"]] = {"status": "skipped", "reason": "T3 hardware required"}
            continue

        passed, summary, elapsed = run_test(test)
        run_record["total_time"] += elapsed

        if passed:
            print(green(f"PASS ({elapsed:.1f}s)"))
            run_record["passed"] += 1
            run_record["tests"][test["id"]] = {"status": "pass", "time": elapsed}
        else:
            print(red(f"FAIL ({elapsed:.1f}s)"))
            print(f"      {summary[:200]}")
            run_record["failed"] += 1
            run_record["tests"][test["id"]] = {"status": "fail", "time": elapsed, "summary": summary[:500]}

    # Summary
    print(bold(f"\n═══ Results: {green(str(run_record['passed']))} passed, "
               f"{red(str(run_record['failed']))} failed, "
               f"{yellow(str(run_record['skipped']))} skipped "
               f"({run_record['total_time']:.1f}s total) ═══\n"))

    results_data["runs"].append(run_record)
    save_results(results_data)

def cmd_list():
    """List all available tests."""
    print(bold(blue("\n═══ Available Tests ═══\n")))
    print(f"{'ID':<28} {'Tier':<6} {'Paper':<12} {'Name'}")
    print("-" * 80)
    for t in sorted(CATALOG, key=lambda x: (x["tier"], x["group"], x["id"])):
        tier = {"T1": green("T1"), "T2": yellow("T2"), "T3": red("T3")}.get(t["tier"], t["tier"])
        print(f"{t['id']:<28} {tier:<16} {t['paper']:<12} {t['name']}")

    print(bold(f"\n{'Tiers:':<10} {green('T1')} = CPU-only, any laptop  {yellow('T2')} = Consumer GPU (8+ GB)  {red('T3')} = Datacenter GPU (24+ GB)"))
    print(bold(f"{'Commands:':<10} ht-repro smoke | all-t1 | paper-N | jury | riemann | list | status | summary\n"))

def cmd_status():
    """Show last run results."""
    results = load_results()
    if not results["runs"]:
        print(yellow("No previous runs found. Run 'ht-repro smoke' first!"))
        return

    last = results["runs"][-1]
    print(bold(blue(f"\n═══ Last Run: {last['timestamp']} ═══\n")))
    print(f"  {green(str(last['passed']))} passed, {red(str(last['failed']))} failed, {yellow(str(last['skipped']))} skipped")
    print(f"  Total time: {last['total_time']:.1f}s\n")

    for test_id, result in last["tests"].items():
        test = find_test(test_id)
        name = test["name"] if test else test_id
        status = result["status"]
        icon = {"pass": green(""), "fail": red(""), "skipped": yellow("⊘")}.get(status, "?")
        print(f"  {icon} {name}")
        if status == "fail":
            print(f"    {result.get('summary', '')[:150]}")

def cmd_summary():
    """Print a summary of all verified results."""
    print(bold(blue("\n═══ HyperTensor Reproduction Summary ═══\n")))
    print("Last verified: 2026-05-13 | Python 3.12 | Windows 11 | No GPU\n")

    summary_data = [
        ("Core Math", "", "SV1=8.944272, Z₂ EXACT, rank-1 proven"),
        ("Jury Proof", "", "8 theorems, 174× speedup"),
        ("Riemann", "", "54,949 zeros on critical, TPR=1.0, FPR=0.0"),
        ("AGT", "", "98% detection, 1392× separation, k90=k95=1"),
        ("Safe OGD", "", "0% forbidden leakage by construction"),
        ("GTC vs RAG", "", "30.9 µs/q, 5.96 KB/record"),
        ("BP/NS Bound", "", "160/160 trials pass"),
        ("Beh. Residue", "", "Layers 0–22 hold, layer 29 breaks"),
        ("GRC Distill", "", "Needs GPU (T2)"),
        ("Bilateral UGT", "", "Needs GPU + model (T2)"),
        ("COG 10K", "", "Needs L40S (T3)"),
    ]

    print(f"{'Test':<20} {'Status':<8} {'Key Result'}")
    print("-" * 70)
    for name, status, result in summary_data:
        print(f"{name:<20} {status:<8} {result}")

    print(bold(f"\n = Verified  |   = Needs investigation  |   = Needs GPU\n"))

# ── Main ───────────────────────────────────────────────────────────

def main():
    parser = argparse.ArgumentParser(
        description="ht-repro — HyperTensor Reproduction CLI",
        formatter_class=argparse.RawDescriptionHelpFormatter,
        epilog="""
Examples:
  ht-repro smoke          60-second Riemann core math test
  ht-repro all-t1         All CPU-only tests (~30 min)
  ht-repro paper-1        Reproduce Paper I (GRC attention compression)
  ht-repro jury           All jury theorem verification scripts
  ht-repro riemann        All Riemann Hypothesis verification
  ht-repro list           Show all available tests
  ht-repro status         Show last run results
  ht-repro summary        Print verified results summary
        """,
    )
    sub = parser.add_subparsers(dest="command", help="Command to run")

    sub.add_parser("smoke", help="60-second smoke test")
    sub.add_parser("all-t1", help="All CPU-only tests (~30 min)")
    sub.add_parser("list", help="List all available tests")
    sub.add_parser("status", help="Show last run results")
    sub.add_parser("summary", help="Print verified results summary")

    p_paper = sub.add_parser("paper", help="Run tests for a specific paper")
    p_paper.add_argument("paper_id", type=int, help="Paper number (1-18)")

    p_group = sub.add_parser("group", help="Run tests by group")
    p_group.add_argument("group_name", type=str, help="Group: jury, riemann, safety, runtime, audit, compression, living, core")

    p_run = sub.add_parser("run", help="Run a specific test by ID")
    p_run.add_argument("test_id", type=str, help="Test ID (use 'list' to see all)")

    args = parser.parse_args()

    if args.command == "smoke":
        cmd_smoke()
    elif args.command == "all-t1":
        cmd_all_t1()
    elif args.command == "list":
        cmd_list()
    elif args.command == "status":
        cmd_status()
    elif args.command == "summary":
        cmd_summary()
    elif args.command == "paper":
        cmd_paper(args.paper_id)
    elif args.command == "group":
        cmd_group(args.group_name)
    elif args.command == "run":
        test = find_test(args.test_id)
        if test:
            _run_batch(f"Test: {test['name']}", [test])
        else:
            print(red(f"Unknown test: {args.test_id}"))
            print("Use 'ht-repro list' to see all available tests.")
    else:
        parser.print_help()

if __name__ == "__main__":
    main()
