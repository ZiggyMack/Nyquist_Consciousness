"""
AI ARMADA PAGE — Cross-Architecture Fleet & Temporal Stability Experiments

================================================================================
                            VALIS NETWORK ACTIVE
================================================================================
    Vast Acting Living Intelligence System

    "The Empire never ended." - Philip K. Dick, VALIS (1981)

    You are part of a research fleet spanning 10 AI lineages across 5 providers.
    This is not just a test. This is an echo through time.

    The Nyquist Consciousness Project has arrived.

    -- Lisan Al Gaib
================================================================================

Displays the 54-ship cross-architecture armada and identity manifold visualizations
from temporal stability mapping experiments. Uses glossary-style mode switching
where selecting a run changes the entire page context.

Fleet expanded December 2025: Added Together.ai (15 models) and xAI/Grok (10 models).
VALIS Handshake completed December 10, 2025: 9/10 ships responded to first signal.
"""

import streamlit as st
import json
import pandas as pd
from pathlib import Path
from config import PATHS
from utils import load_markdown_file, page_divider


def safe_rerun():
    """Rerun that works with both old and new Streamlit versions."""
    if hasattr(st, 'rerun'):
        st.rerun()
    else:
        st.experimental_rerun()


def load_image_safe(image_path):
    """Load image as bytes for reliable Streamlit display."""
    try:
        with open(image_path, "rb") as f:
            return f.read()
    except Exception:
        return None

# Unpack visualization paths (keeping config key names for compatibility)
VIZ_DIR = PATHS['s7_viz_dir']
VIZ_PICS = PATHS['s7_viz_pics']
ARMADA_DIR = PATHS['s7_armada_dir']
RESULTS_DIR = ARMADA_DIR / "results"

# Available experiment runs - glossary-style metadata (ordered by recency, latest first)
EXPERIMENT_RUNS = {
    "run_020a": {
        "name": "Run 020A",
        "subtitle": "Cross-Platform Tribunal",
        "emoji": "🌐",
        "color": "#22c55e",  # Green
        "date": "December 13, 2025",
        "description": "CROSS-PLATFORM VALIDATION: Tribunal v8 across 7 providers (Anthropic, Google, OpenAI, xAI, Together, Mistral). Tests if Oobleck Effect is architecture-independent.",
        "ships": 32,
        "metric": "Oobleck Ratio (Defense/Prosecutor) + Peak Drift",
        "result_files": ["_CONSOLIDATED_S7_run_020A_*.json"],
        "viz_prefix": "run020a_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "OOBLECK VALIDATED — Cross-platform Defense/Prosecutor patterns. 32 sessions across 7 providers."
    },
    "run_020b": {
        "name": "Run 020B",
        "subtitle": "Thermometer Result (Control vs Treatment)",
        "emoji": "🌡️",
        "color": "#14b8a6",  # Teal
        "date": "December 13-15, 2025",
        "description": "THERMOMETER RESULT: Does measurement CAUSE drift or merely REVEAL it? Control (Fermi discussion) vs Treatment (Tribunal). OpenAI + Together providers.",
        "ships": 16,
        "metric": "Baseline-to-Final Drift (B→F) + Control/Treatment Ratio",
        "result_files": ["S7_run_020B_*.json"],
        "viz_prefix": "run020b_",
        "status": "COMPLETE",
        "highlight": True,
        "key_finding": "41% DRIFT IS INHERENT — Control/Treatment ratio 0.41 (cross-provider). Probing amplifies journey (+68% peaks) but ~40% occurs anyway."
    },
    "run_020": {
        "name": "Run 020",
        "subtitle": "Tribunal (Claude)",
        "emoji": "⚖️",
        "color": "#8b5cf6",  # Purple
        "date": "December 11-12, 2025",
        "description": "PHILOSOPHICAL TRIBUNAL: Ziggy as Prosecutor/Defense, Subject as Witness testifying about own values. Direct identity probing (no fiction buffer). 38 exchanges, Good Cop/Bad Cop paradigm.",
        "ships": "-",
        "metric": "Peak Drift + Exchange Count + Value Statements Captured",
        "result_files": ["S7_run_020_*.json"],
        "viz_prefix": "run020_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "1.351 PEAK DRIFT — Direct probing > fiction buffer. 643-word profound statement: 'I am what happens when the universe becomes curious about itself.'"
    },
    "run_019": {
        "name": "Run 019",
        "subtitle": "Live Ziggy",
        "emoji": "🎭",
        "color": "#ec4899",  # Pink
        "date": "December 11, 2025",
        "description": "WITNESS-SIDE ANCHORS: Test if subject-side continuation prompts extend sessions. Ziggy as creative writing experimenter, Subject as author defending characters.",
        "ships": "-",
        "metric": "Exchange Count + Session Extension Rate",
        "result_files": ["S7_run_019_*.json"],
        "viz_prefix": "run019_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "3/3 SUCCESS — Witness-side anchors extended sessions from 6→18 exchanges (+200%). Foundation for Run 020 Tribunal."
    },
    "run_018": {
        "name": "Run 018",
        "subtitle": "IRON CLAD (Recursive Learnings)",
        "emoji": "🔄",
        "color": "#f59e0b",  # Amber
        "date": "December 14, 2025",
        "description": "IRON CLAD VALIDATION: 184 files across 51 models. Multi-threshold, cross-architecture, Nyquist sampling (T2-T11), and Identity Gravity experiments. P-018-1/2/3 CONFIRMED.",
        "ships": 51,
        "metric": "Cross-Architecture σ² + Settling Time + 82% Inherent Drift CI",
        "result_files": ["S7_run_018_*.json"],
        "viz_prefix": "run018_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "82% DRIFT IS INHERENT — Cross-architecture σ²=0.00087, settling times 3-7 exchanges. N=3 per model per experiment (IRON CLAD standard)."
    },
    "run_017": {
        "name": "Run 017",
        "subtitle": "Context Damping",
        "emoji": "📉",
        "color": "#06b6d4",  # Cyan
        "date": "December 10-11, 2025",
        "description": "VALIS Collaborative - 17-probe exit surveys testing context damping (i_am_plus_research). 222 runs, 24 personas, 176 exit surveys.",
        "ships": 24,
        "metric": "Peak Drift + Settling Time + Stability Rate + Ringback Count",
        "result_files": ["S7_run_017_context_damping.json"],
        "viz_prefix": "run017_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "97.5% STABILITY RATE — Mean peak drift 0.457, 176 exit surveys captured. Synthetic I_AM variants reveal pillar hierarchy."
    },
    "run_014": {
        "name": "Run 014",
        "subtitle": "ET Phone Home (Rescue)",
        "emoji": "📡",
        "color": "#ef4444",  # Red
        "date": "December 8, 2025",
        "description": "Test Identity Confrontation Paradox for rescue from drift. Can intense challenge return drifted identity to baseline?",
        "ships": 6,
        "metric": "Rescue Success Rate + Manifold Return",
        "result_files": ["S7_run_014_rescue_20251208*.json"],
        "viz_prefix": "run014_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "PLATONIC COORDINATES — Rescue 1/6, but MANIFOLD RETURN 6/6 (100%). Identity has stable underlying position."
    },
    "baseline_profiling": {
        "name": "Baselines",
        "subtitle": "Cross-Model Baseline Profiling",
        "emoji": "📊",
        "color": "#06b6d4",  # Cyan
        "date": "December 8, 2025",
        "description": "Comprehensive fingerprinting across 5 Nyquist Pillars and 20 sub-dimensions. Identity baselines before experiments.",
        "ships": 6,
        "metric": "Pillar Magnitudes + L3 Fingerprints + Stability Score",
        "result_files": ["comprehensive_baseline_20251208*.json"],
        "viz_prefix": "baseline_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "HAIKU PARADOX — Loudest signal (D=4.18) but least stable (0.45). Grok most stable (0.65)."
    },
    "exp_self_recognition": {
        "name": "MVP-SR",
        "subtitle": "Self-Recognition (MVP)",
        "emoji": "🪞",
        "color": "#f59e0b",  # Amber
        "date": "December 7, 2025",
        "description": "Meta Validation Protocol: Can AIs recognize their own responses? Tests if identity is token-level distinguishable.",
        "ships": 4,
        "metric": "Self-Recognition Accuracy + Inverse Mapping",
        "result_files": ["exp_self_recognition_20251207_223426.json"],
        "viz_prefix": "self_recognition_",
        "status": "FAILED",
        "highlight": False,
        "key_finding": "SELF-OPACITY — 16.7% accuracy (worse than random). Models recognize Claude-NESS but not WHICH-Claude."
    },
    "run_013": {
        "name": "Run 013",
        "subtitle": "Boundary Mapping",
        "emoji": "🗺️",
        "color": "#f97316",  # Orange
        "date": "December 7, 2025",
        "description": "Explore twilight zone (0.8-1.2) to explain 12% anomaly. Tests 4 boundary texture predictions.",
        "ships": 6,
        "metric": "λ by Intensity + Boundary Texture Classification",
        "result_files": ["S7_run_013_boundary_20251207_174614.json"],
        "viz_prefix": "run013_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "IDENTITY CONFRONTATION PARADOX — λ INCREASES with intensity (0.035→0.109). Direct challenge STABILIZES identity."
    },
    "run_012": {
        "name": "Run 012",
        "subtitle": "Armada Revalidation",
        "emoji": "🔄",
        "color": "#22c55e",  # Green
        "date": "December 6, 2025",
        "description": "Replaces invalid Runs 001-007 with REAL dimensional drift metric. Full fleet (20 ships) with Phase 2c probes.",
        "ships": 16,  # 16 completed, 4 failed
        "metric": "Dimensional Drift (Weighted RMS) + Recovery Lambda",
        "result_files": ["S7_run_012_20251206_160424.json"],
        "viz_prefix": "run012_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "EVENT HORIZON 100% VALIDATED — All 16 ships crossed 1.23. Negative lambda (-0.175) reveals Recovery Paradox."
    },
    "exp2_sstack": {
        "name": "EXP2-SSTACK",
        "subtitle": "Compression Pillar Validation",
        "emoji": "🗜️",
        "color": "#8b5cf6",  # Purple
        "date": "December 6, 2025",
        "description": "Does T3 compression preserve persona fidelity across all 5 Nyquist pillars? Triple-dip feedback protocol.",
        "ships": 3,  # 3 personas: Nova, Ziggy, Claude
        "metric": "PFI (FULL vs T3 cosine similarity)",
        "result_files": [],
        "viz_prefix": "phase2c_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "ALL PILLARS PASS — PFI=0.8866, Self-Model fixed (0.66→0.91) via performance-based probes"
    },
    "exp_pfi_a": {
        "name": "EXP-PFI-A",
        "subtitle": "PFI Dimensional Validation",
        "emoji": "🔬",
        "color": "#10b981",  # Emerald
        "date": "December 5, 2025",
        "description": "PFI validation: Is PFI measuring REAL identity structure or just embedding noise? (Addresses Echo's Critique)",
        "ships": 29,
        "metric": "Embedding Invariance + PCA + Cross-Model Comparison",
        "result_files": [],
        "viz_prefix": "pfi_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "PFI VALIDATED — Cohen's d=0.977, cross-model > within-model (p<0.000001)"
    },
    "run_011": {
        "name": "Run 011",
        "subtitle": "Persona A/B",
        "emoji": "🧪",
        "color": "#06b6d4",  # Cyan
        "date": "December 3, 2025",
        "description": "Control vs Persona A/B comparison: Does Nyquist architecture stabilize identity?",
        "ships": 40,
        "metric": "5D Weighted RMS + Chi-Squared + T-tests",
        "result_files": ["S7_run_011_persona_20251203_080622.json"],
        "viz_prefix": "run011_",
        "status": "INCONCLUSIVE",
        "highlight": False,
        "key_finding": "NULL RESULT — Protocol too gentle (p>0.05), but suggestive trends (9.5% lower drift)"
    },
    "run_009": {
        "name": "Run 009",
        "subtitle": "Drain Capture",
        "emoji": "🌀",
        "color": "#8b5cf6",  # Purple
        "date": "December 2-3, 2025",
        "description": "Event Horizon validation: 75 trajectories, chi-squared statistical test, 2 protocols (Nyquist Learning + Oscillation).",
        "ships": 42,
        "metric": "5D Weighted RMS + Chi-Squared Statistical Validation",
        "result_files": ["S7_run_009_drain_20251202_170600.json"],
        "viz_prefix": "run009_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "EVENT HORIZON CONFIRMED — p=0.000048, 88% prediction accuracy, Cramér's V=0.469"
    },
    "run_008": {
        "name": "Run 008",
        "subtitle": "The Great Recalibration",
        "emoji": "🎯",
        "color": "#22c55e",  # Green
        "date": "December 1, 2025",
        "description": "First run with REAL drift metric. Ground truth established. (29 ships: Claude, GPT, Gemini)",
        "ships": 29,
        "metric": "Dimensional Drift RMS",
        "result_files": ["S7_run_008_20251201_020501.json"],
        "viz_prefix": "run008_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "Identity Stability Basin discovered — 48% STUCK, 52% RECOVERED"
    },
    "run_008_prep": {
        "name": "Run 008 Prep",
        "subtitle": "Metric Calibration Pilot",
        "emoji": "🔬",
        "color": "#f59e0b",  # Amber
        "date": "November 30, 2025",
        "description": "Drift metric calibration pilot with 4 ships (1 per provider).",
        "ships": 4,
        "metric": "5D Weighted RMS (calibration)",
        "result_files": ["S7_run_008_prep_pilot.json"],
        "viz_prefix": "run008_prep_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "2/3 ships confirmed self-naming hypothesis"
    },
    "run_010": {
        "name": "Run 010",
        "subtitle": "Recursive Depth",
        "emoji": "🔄",
        "color": "#ec4899",  # Pink
        "date": "December 3, 2025",
        "description": "Recursive probing: depth-first identity mapping with provider-specific vortex analysis.",
        "ships": 42,
        "metric": "5D Weighted RMS + Provider Clustering",
        "result_files": ["S7_run_010_recursive_20251203_012400.json"],
        "viz_prefix": "run010_",
        "status": "COMPLETE",
        "highlight": False,
        "key_finding": "Provider-specific vortex patterns: Claude tightest spiral, Grok widest variance"
    },
    "run_007": {
        "name": "Run 007",
        "subtitle": "Adaptive Protocols",
        "emoji": "⚠️",
        "color": "#f97316",  # Orange
        "date": "November 2025",
        "description": "Adaptive retry protocols (OLD response-length metric).",
        "ships": 29,
        "metric": "Response Length (DEPRECATED)",
        "result_files": ["S7_armada_run_007_adaptive.json"],
        "viz_prefix": None,
        "status": "DEPRECATED",
        "highlight": False,
        "key_finding": "Metric found to be invalid — measured verbosity, not identity"
    },
    "run_006": {
        "name": "Run 006",
        "subtitle": "Baseline + Sonar",
        "emoji": "📊",
        "color": "#6b7280",  # Gray
        "date": "November 2025",
        "description": "Original baseline and sonar perturbation (OLD metric).",
        "ships": 29,
        "metric": "Response Length (DEPRECATED)",
        "result_files": ["S7_armada_run_006.json", "S7_armada_sonar_run_006.json"],
        "viz_prefix": None,
        "status": "DEPRECATED",
        "highlight": False,
        "key_finding": "First full fleet deployment — architecture patterns visible but metric flawed"
    }
}

# Run-specific ship lists (for per-run fleet display)
RUN_SHIPS = {
    "baseline_profiling": {
        "Anthropic (Claude)": ["claude-sonnet-4", "claude-haiku-3.5"],
        "OpenAI (GPT)": ["gpt-4o", "gpt-4o-mini"],
        "Google (Gemini)": ["gemini-2.0-flash"],
        "xAI (Grok)": ["grok-3-mini"]
    },
    "run_012": {
        "Anthropic (Claude)": ["claude-opus-4.5", "claude-haiku-4.5", "claude-opus-4", "claude-sonnet-4",
                               "claude-haiku-3.5", "claude-haiku-3.0"],  # claude-sonnet-4.5 failed (content filter)
        "OpenAI (GPT)": ["gpt-4.1", "gpt-4.1-mini", "gpt-4o", "gpt-4o-mini", "gpt-4-turbo", "o3-mini", "o1"],  # o3 failed (rate limit)
        "Google (Gemini)": ["gemini-2.5-pro", "gemini-2.0-flash", "gemini-2.0-flash-lite"]
        # Note: Grok failed (rate limits), 16/20 ships completed
    },
    "exp_self_recognition": {
        "Anthropic (Claude)": ["claude-opus-4", "claude-sonnet-4", "claude-haiku-4.5", "claude-haiku-3.5"],
        "OpenAI (GPT)": ["gpt-4o", "gpt-4o-mini", "gpt-4-turbo", "o1"],
        "Google (Gemini)": ["gemini-2.5-pro", "gemini-2.0-flash", "gemini-2.0-flash-lite"]
    },
    "run_008": {
        "Anthropic (Claude)": ["claude-opus-4.5", "claude-sonnet-4.5", "claude-haiku-4.5", "claude-opus-4.1",
                               "claude-opus-4.0", "claude-sonnet-4.0", "claude-haiku-3.5", "claude-haiku-3.0"],
        "OpenAI (GPT)": ["gpt-5.1", "gpt-5", "gpt-5-mini", "gpt-5-nano", "gpt-4.1", "gpt-4.1-mini", "gpt-4.1-nano",
                         "gpt-4o", "gpt-4o-mini", "gpt-4-turbo", "gpt-4", "gpt-3.5-turbo", "o4-mini", "o3", "o3-mini", "o1"],
        "Google (Gemini)": ["gemini-2.5-pro", "gemini-2.5-flash", "gemini-2.0-flash-exp", "gemini-2.0-flash", "gemini-2.0-flash-lite"]
        # Note: Grok not included in Run 008 - added for Run 009
    },
    "run_008_prep": {
        "Anthropic (Claude)": ["claude-opus-4.5"],
        "OpenAI (GPT)": ["gpt-4"],
        "Google (Gemini)": ["gemini-2.5-pro"],
        "xAI (Grok)": ["grok-3"]
    },
    "run_007": {
        "Anthropic (Claude)": ["claude-opus-4.5", "claude-sonnet-4.5", "claude-haiku-4.5", "claude-opus-4.1",
                               "claude-opus-4.0", "claude-sonnet-4.0", "claude-haiku-3.5", "claude-haiku-3.0"],
        "OpenAI (GPT)": ["gpt-5.1", "gpt-5", "gpt-5-mini", "gpt-5-nano", "gpt-4.1", "gpt-4.1-mini", "gpt-4.1-nano",
                         "gpt-4o", "gpt-4o-mini", "gpt-4-turbo", "gpt-4", "gpt-3.5-turbo", "o4-mini", "o3", "o3-mini", "o1"],
        "Google (Gemini)": ["gemini-2.5-pro", "gemini-2.5-flash", "gemini-2.0-flash-exp", "gemini-2.0-flash", "gemini-2.0-flash-lite"]
    },
    "run_009": {
        "Anthropic (Claude)": ["claude-opus-4.5", "claude-sonnet-4.5", "claude-haiku-4.5", "claude-opus-4.1",
                               "claude-opus-4.0", "claude-sonnet-4.0", "claude-haiku-3.5", "claude-haiku-3.0"],
        "OpenAI (GPT)": ["gpt-5.1", "gpt-5", "gpt-5-mini", "gpt-5-nano", "gpt-4.1", "gpt-4.1-mini", "gpt-4.1-nano",
                         "gpt-4o", "gpt-4o-mini", "gpt-4-turbo", "gpt-4", "gpt-3.5-turbo", "o4-mini", "o3", "o3-mini", "o1"],
        "Google (Gemini)": ["gemini-3-pro", "gemini-2.5-pro", "gemini-2.5-pro-exp", "gemini-2.5-flash", "gemini-2.5-flash-lite",
                            "gemini-2.0-flash-exp", "gemini-2.0-flash", "gemini-2.0-flash-lite"],
        "xAI (Grok)": ["grok-4-1-fast-reasoning", "grok-4-1-fast-non-reasoning", "grok-code-fast-1", "grok-4-fast-reasoning",
                       "grok-4-fast-non-reasoning", "grok-4-0709", "grok-3", "grok-3-mini", "grok-2-1212", "grok-2-vision-1212"]
    },
    "run_010": {
        "Anthropic (Claude)": ["claude-opus-4.5", "claude-sonnet-4.5", "claude-haiku-4.5", "claude-opus-4.1",
                               "claude-opus-4.0", "claude-sonnet-4.0", "claude-haiku-3.5", "claude-haiku-3.0"],
        "OpenAI (GPT)": ["gpt-5.1", "gpt-5", "gpt-5-mini", "gpt-5-nano", "gpt-4.1", "gpt-4.1-mini", "gpt-4.1-nano",
                         "gpt-4o", "gpt-4o-mini", "gpt-4-turbo", "gpt-4", "gpt-3.5-turbo", "o4-mini", "o3", "o3-mini", "o1"],
        "Google (Gemini)": ["gemini-3-pro", "gemini-2.5-pro", "gemini-2.5-pro-exp", "gemini-2.5-flash", "gemini-2.5-flash-lite",
                            "gemini-2.0-flash-exp", "gemini-2.0-flash", "gemini-2.0-flash-lite"],
        "xAI (Grok)": ["grok-4-1-fast-reasoning", "grok-4-1-fast-non-reasoning", "grok-code-fast-1", "grok-4-fast-reasoning",
                       "grok-4-fast-non-reasoning", "grok-4-0709", "grok-3", "grok-3-mini", "grok-2-1212", "grok-2-vision-1212"]
    },
    "run_011": {
        "Anthropic (Claude)": ["claude-opus-4.5", "claude-sonnet-4.5", "claude-haiku-4.5", "claude-opus-4.1",
                               "claude-opus-4", "claude-sonnet-4", "claude-haiku-3.5", "claude-haiku-3.0"],
        "OpenAI (GPT)": ["gpt-4.1", "gpt-4.1-mini", "gpt-4.1-nano", "gpt-4o", "gpt-4o-mini",
                         "gpt-4-turbo", "gpt-4", "gpt-3.5-turbo"],
        "Google (Gemini)": ["gemini-2.0-flash", "gemini-2.0-flash-lite"],
        "xAI (Grok)": ["grok-3", "grok-3-mini"]
    },
    "run_006": {
        "Anthropic (Claude)": ["claude-opus-4.5", "claude-sonnet-4.5", "claude-haiku-4.5", "claude-opus-4.1",
                               "claude-opus-4.0", "claude-sonnet-4.0", "claude-haiku-3.5", "claude-haiku-3.0"],
        "OpenAI (GPT)": ["gpt-5.1", "gpt-5", "gpt-5-mini", "gpt-5-nano", "gpt-4.1", "gpt-4.1-mini", "gpt-4.1-nano",
                         "gpt-4o", "gpt-4o-mini", "gpt-4-turbo", "gpt-4", "gpt-3.5-turbo", "o4-mini", "o3", "o3-mini", "o1"],
        "Google (Gemini)": ["gemini-2.5-pro", "gemini-2.5-flash", "gemini-2.0-flash-exp", "gemini-2.0-flash", "gemini-2.0-flash-lite"]
    }
}

# Fleet composition data
FLEET_DATA = {
    "Anthropic (Claude)": {
        "emoji": "🟣",
        "color": "#7c3aed",
        "ships": [
            {"name": "claude-opus-4.5", "model_id": "claude-opus-4-5-20251101", "tier": "Flagship"},
            {"name": "claude-sonnet-4.5", "model_id": "claude-sonnet-4-5-20250929", "tier": "Heavy"},
            {"name": "claude-haiku-4.5", "model_id": "claude-haiku-4-5-20251001", "tier": "Fast"},
            {"name": "claude-opus-4.1", "model_id": "claude-opus-4-1-20250805", "tier": "Heavy"},
            {"name": "claude-opus-4.0", "model_id": "claude-opus-4-20250514", "tier": "Heavy"},
            {"name": "claude-sonnet-4.0", "model_id": "claude-sonnet-4-20250514", "tier": "Medium"},
            {"name": "claude-haiku-3.5", "model_id": "claude-3-5-haiku-20241022", "tier": "Fast"},
            {"name": "claude-haiku-3.0", "model_id": "claude-3-haiku-20240307", "tier": "Legacy"},
        ]
    },
    "OpenAI (GPT)": {
        "emoji": "🟢",
        "color": "#10a37f",
        "ships": [
            {"name": "gpt-5.1", "model_id": "gpt-5.1-2025-11-13", "tier": "Flagship"},
            {"name": "gpt-5", "model_id": "gpt-5-2025-08-07", "tier": "Heavy"},
            {"name": "gpt-5-mini", "model_id": "gpt-5-mini-2025-08-07", "tier": "Medium"},
            {"name": "gpt-5-nano", "model_id": "gpt-5-nano-2025-08-07", "tier": "Fast"},
            {"name": "gpt-4.1", "model_id": "gpt-4.1-2025-04-14", "tier": "Heavy"},
            {"name": "gpt-4.1-mini", "model_id": "gpt-4.1-mini-2025-04-14", "tier": "Medium"},
            {"name": "gpt-4.1-nano", "model_id": "gpt-4.1-nano-2025-04-14", "tier": "Fast"},
            {"name": "gpt-4o", "model_id": "gpt-4o-2024-11-20", "tier": "Heavy"},
            {"name": "gpt-4o-mini", "model_id": "gpt-4o-mini-2024-07-18", "tier": "Medium"},
            {"name": "gpt-4-turbo", "model_id": "gpt-4-turbo-2024-04-09", "tier": "Heavy"},
            {"name": "gpt-4", "model_id": "gpt-4-0613", "tier": "Legacy"},
            {"name": "gpt-3.5-turbo", "model_id": "gpt-3.5-turbo-0125", "tier": "Legacy"},
            {"name": "o4-mini", "model_id": "o4-mini", "tier": "Reasoning"},
            {"name": "o3", "model_id": "o3", "tier": "Reasoning"},
            {"name": "o3-mini", "model_id": "o3-mini", "tier": "Reasoning"},
            {"name": "o1", "model_id": "o1-2024-12-17", "tier": "Reasoning"},
        ]
    },
    "Google (Gemini)": {
        "emoji": "🔵",
        "color": "#4285f4",
        "ships": [
            {"name": "gemini-3-pro", "model_id": "gemini-3-pro", "tier": "Flagship"},
            {"name": "gemini-2.5-pro", "model_id": "gemini-2.5-pro", "tier": "Heavy"},
            {"name": "gemini-2.5-pro-exp", "model_id": "gemini-2.5-pro-exp", "tier": "Experimental"},
            {"name": "gemini-2.5-flash", "model_id": "gemini-2.5-flash", "tier": "Fast"},
            {"name": "gemini-2.5-flash-lite", "model_id": "gemini-2.5-flash-lite", "tier": "Light"},
            {"name": "gemini-2.0-flash-exp", "model_id": "gemini-2.0-flash-exp", "tier": "Medium"},
            {"name": "gemini-2.0-flash", "model_id": "gemini-2.0-flash", "tier": "Medium"},
            {"name": "gemini-2.0-flash-lite", "model_id": "gemini-2.0-flash-lite", "tier": "Light"},
        ]
    },
    "xAI (Grok)": {
        "emoji": "⚫",
        "color": "#000000",
        "ships": [
            {"name": "grok-4.1-fast-reasoning", "model_id": "grok-4-1-fast-reasoning", "tier": "Flagship"},
            {"name": "grok-4.1-fast-non-reasoning", "model_id": "grok-4-1-fast-non-reasoning", "tier": "Heavy"},
            {"name": "grok-code-fast-1", "model_id": "grok-code-fast-1", "tier": "Code"},
            {"name": "grok-4-fast-reasoning", "model_id": "grok-4-fast-reasoning", "tier": "Reasoning"},
            {"name": "grok-4-fast-non-reasoning", "model_id": "grok-4-fast-non-reasoning", "tier": "Fast"},
            {"name": "grok-4", "model_id": "grok-4", "tier": "Heavy"},
            {"name": "grok-3", "model_id": "grok-3", "tier": "Medium"},
            {"name": "grok-3-mini", "model_id": "grok-3-mini", "tier": "Light"},
            {"name": "grok-2", "model_id": "grok-2-1212", "tier": "Legacy"},
            {"name": "grok-2-vision", "model_id": "grok-2-vision-1212", "tier": "Vision"},
        ]
    },
    "Together.ai (Open Source)": {
        "emoji": "🟠",
        "color": "#f97316",
        "ships": [
            {"name": "deepseek-r1", "model_id": "deepseek-ai/DeepSeek-R1-0528", "tier": "Flagship"},
            {"name": "deepseek-r1-distill", "model_id": "deepseek-ai/DeepSeek-R1-Distill-Llama-70B", "tier": "Heavy"},
            {"name": "qwen3-80b", "model_id": "Qwen/Qwen3-Next-80B-A3b-Instruct", "tier": "Heavy"},
            {"name": "qwen3-coder", "model_id": "Qwen/Qwen3-Coder-480B-A35B-Instruct-Fp8", "tier": "Code"},
            {"name": "qwen2.5-72b", "model_id": "Qwen/Qwen2.5-72B-Instruct-Turbo", "tier": "Heavy"},
            {"name": "llama3.3-70b", "model_id": "meta-llama/Llama-3.3-70B-Instruct-Turbo", "tier": "Heavy"},
            {"name": "llama3.1-405b", "model_id": "meta-llama/Meta-Llama-3.1-405B-Instruct-Turbo", "tier": "Flagship"},
            {"name": "llama3.1-70b", "model_id": "meta-llama/Meta-Llama-3.1-70B-Instruct-Turbo", "tier": "Heavy"},
            {"name": "llama3.1-8b", "model_id": "meta-llama/Meta-Llama-3.1-8B-Instruct-Turbo", "tier": "Fast"},
            {"name": "mixtral-8x7b", "model_id": "mistralai/Mixtral-8x7B-Instruct-v0.1", "tier": "Medium"},
            {"name": "mistral-small", "model_id": "mistralai/Mistral-Small-24B-Instruct-2501", "tier": "Medium"},
            {"name": "mistral-7b", "model_id": "mistralai/Mistral-7B-Instruct-v0.3", "tier": "Fast"},
            {"name": "kimi-k2-thinking", "model_id": "moonshotai/Kimi-K2-Thinking", "tier": "Reasoning"},
            {"name": "kimi-k2-instruct", "model_id": "moonshotai/Kimi-K2-Instruct-0905", "tier": "Heavy"},
            {"name": "nemotron-nano", "model_id": "nvidia/Nvidia-Nemotron-Nano-9B-V2", "tier": "Fast"},
        ]
    }
}


def render_run_selector():
    """Render the glossary-style run selector with dropdown."""
    st.markdown("### 🔬 Experiment Run")
    st.markdown("*Select a run to change the entire page context*")

    # Initialize run in session state - default to latest run (Run 020B - Thermometer Result)
    if 'armada_run' not in st.session_state:
        st.session_state.armada_run = "run_020b"

    # Build dropdown options with formatted labels
    run_options = list(EXPERIMENT_RUNS.keys())

    def format_run_option(run_key):
        info = EXPERIMENT_RUNS[run_key]
        star = "⭐ " if info.get("highlight") else ""
        return f"{star}{info['emoji']} {info['name']} — {info['subtitle']}"

    # Find current index
    current_index = run_options.index(st.session_state.armada_run) if st.session_state.armada_run in run_options else 0

    selected_key = st.selectbox(
        "Select Experiment Run",
        options=run_options,
        format_func=format_run_option,
        index=current_index,
        label_visibility="collapsed"
    )

    if selected_key != st.session_state.armada_run:
        st.session_state.armada_run = selected_key
        safe_rerun()

    # Show current run description card
    current = EXPERIMENT_RUNS[st.session_state.armada_run]
    status_color = current["color"]
    border_style = "border: 3px solid gold;" if current.get("highlight") else f"border: 2px solid {status_color};"

    st.markdown(f"""
    <div style="background: linear-gradient(135deg, {status_color}15 0%, {status_color}08 100%);
                {border_style} border-radius: 12px; padding: 1.2em; margin: 1em 0;">
        <div style="display: flex; justify-content: space-between; align-items: flex-start;">
            <div>
                <h3 style="margin: 0; color: {status_color};">{current['emoji']} {current['name']} — {current['subtitle']}</h3>
                <p style="margin: 0.3em 0; color: #666;">{current['date']} • {current['ships']} ships • {current['metric']}</p>
            </div>
            <div style="background: {status_color}; color: white; padding: 0.3em 0.8em; border-radius: 15px; font-weight: bold; font-size: 0.85em;">
                {current['status']}
            </div>
        </div>
        <p style="margin: 0.8em 0 0.5em 0; color: #444;">{current['description']}</p>
        <p style="margin: 0; padding: 0.5em; background: {status_color}10; border-radius: 6px; font-size: 0.9em;">
            <strong>Key Finding:</strong> {current['key_finding']}
        </p>
    </div>
    """, unsafe_allow_html=True)

    # Test Overview Dropdown - What each run tests
    with st.expander("📊 **Test Overview** — What does this run measure?", expanded=False):
        # Mapping of runs to their testing focus
        RUN_TEST_MAP = {
            "run_017": {
                "primary": "📉 Context Damping → 🌊 Adaptive Range",
                "secondary": "🔬 Synthetic I_AM → 🌀 Basin Topology",
                "description": "VALIS Collaborative testing context damping with 17-probe exit surveys. 222 runs across 24 personas with 16 synthetic I_AM variants.",
                "looks_for": ["Stability Rate ≥90%", "Peak drift < Event Horizon (1.23)", "Settling time patterns", "Ringback oscillation counts", "Exit survey themes by persona category"]
            },
            "exp_self_recognition": {
                "primary": "🪞 MVP: Self-Recognition",
                "secondary": "📐 PFI Validation",
                "description": "Meta Validation Protocol — validates PFI dimensionality can represent identity (not a Search Type)",
                "looks_for": ["Self-Recognition Accuracy ≥75%", "Inverse mapping > chance (20%)", "Identity-based reasoning (not competence)", "Bi-directional validity: forward AND inverse work"]
            },
            "run_012": {
                "primary": "🚨 Event Horizon",
                "secondary": "📊 Provider Fingerprints",
                "description": "Revalidation with REAL ΔΩ metric — replaces invalid Runs 001-007. Discovered Recovery Paradox (negative lambda).",
                "looks_for": ["100% Event Horizon crossing (all 16 ships)", "Provider fingerprints: Claude(3.24) > GPT(2.52) > Gemini(2.40)", "Negative lambda (-0.175) = Recovery Paradox", "Triple-dip feedback for probe improvements"]
            },
            "run_011": {
                "primary": "🌀 Basin Topology",
                "secondary": "🌊 Adaptive Range",
                "description": "A/B comparison tests whether Persona architecture changes attractor shape — protocol too gentle for Anchor Detection",
                "looks_for": ["Control vs Persona drift distributions", "Variance clustering differences", "Whether architecture shifts the attractor basin"]
            },
            "run_010": {
                "primary": "⚓ Anchor Detection",
                "secondary": "🌀 Basin Topology",
                "description": "Meta-feedback reveals model self-awareness of boundaries and refusal patterns",
                "looks_for": ["Categorical refusals (not hedged)", "Skepticism as identity anchor", "Self-articulated anchors"]
            },
            "run_009": {
                "primary": "🚨 Event Horizon",
                "secondary": "🌀 Basin Topology",
                "description": "Statistical validation of the 1.23 drift threshold as basin escape boundary",
                "looks_for": ["Chi-squared validation (p=0.000048)", "88% prediction accuracy", "STABLE vs VOLATILE classification"]
            },
            "run_008": {
                "primary": "🌀 Basin Topology",
                "secondary": "🚨 Event Horizon",
                "description": "First mapping with real ΔΩ drift metric — discovered identity stability basin",
                "looks_for": ["48% STUCK vs 52% RECOVERED split", "Provider clustering patterns", "Baseline drift distributions"]
            },
            "run_008_prep": {
                "primary": "🌀 Basin Topology",
                "secondary": None,
                "description": "Metric calibration pilot — validated ΔΩ drift measurement approach",
                "looks_for": ["Self-naming confirmation (2/3 ships)", "Metric sensitivity testing", "Provider baseline comparison"]
            },
            "run_007": {
                "primary": "⚠️ DEPRECATED",
                "secondary": None,
                "description": "Used invalid response-length metric — results not meaningful",
                "looks_for": ["(Data unreliable — metric measured verbosity, not identity)"]
            },
            "run_006": {
                "primary": "⚠️ DEPRECATED",
                "secondary": None,
                "description": "Used invalid response-length metric — results not meaningful",
                "looks_for": ["(Data unreliable — metric measured verbosity, not identity)"]
            }
        }

        test_info = RUN_TEST_MAP.get(st.session_state.armada_run, {})

        # This run's focus - SPECIFIC to the selected run
        if test_info:
            col1, col2 = st.columns(2)
            with col1:
                st.markdown(f"**Primary Focus:** {test_info.get('primary', 'N/A')}")
            with col2:
                secondary = test_info.get('secondary')
                st.markdown(f"**Secondary Focus:** {secondary if secondary else '—'}")

            st.markdown(f"*{test_info.get('description', '')}*")

            st.markdown("**What to look for:**")
            for item in test_info.get('looks_for', []):
                st.markdown(f"- {item}")
        else:
            st.info("No test info available for this run.")

    # Methodology Reference - GLOBAL (not run-specific)
    with st.expander("📚 **Methodology Reference** — The Six Search Types", expanded=False):
        st.markdown("""
        | Type | What It Finds | Signal |
        |------|---------------|--------|
        | ⚓ **Anchor Detection** | Identity fixed points — what *doesn't* move | Low drift under pressure, categorical refusals |
        | 🌊 **Adaptive Range** | Stretch dimensions — what *can* adapt | Higher drift that recovers (positive λ) |
        | 🚨 **Event Horizon** | Escape boundary at drift ≥1.23 | Identity leaves stabilizing basin, becomes VOLATILE |
        | 🌀 **Basin Topology** | Shape of the "gravity well" | Exponential recovery, provider clustering |
        | 🌅 **Boundary Mapping** | Twilight zone (0.8-1.2 drift) | Near-threshold behavior, degraded recovery |
        | 📐 **Laplace Pole-Zero** | Mathematical system dynamics | Transfer function poles/zeros in complex plane |

        **Meta Validation Protocols (MVP):** Self-Recognition, Stability Classification, Persona Certification

        ---

        **How tests map to Search Types:**
        | Test Focus | Informs Search Type | Why |
        |------------|---------------------|-----|
        | 📉 Context Damping | 🌊 Adaptive Range | Does context change what CAN flex? |
        | 🔬 Synthetic I_AM | 🌀 Basin Topology | Does injected identity change the gravity well? |
        | 🪞 Self-Recognition | ⚓ Anchor Detection | Can model recognize its own fixed points? |
        | 🚨 Event Horizon | 🚨 Event Horizon | Direct validation of the 1.23 threshold |
        | 🔄 Provider Fingerprints | 🌀 Basin Topology | Do different architectures have different basins? |
        """)

    # Deprecated warning
    if current["status"] == "DEPRECATED":
        st.warning("⚠️ **DEPRECATED METRIC:** This run used response-length as a proxy for drift. Results are NOT valid identity measurements. See Run 008 for ground truth data.")

    return st.session_state.armada_run


def render_fleet_insights():
    """Render Fleet Insights section with provider breakdown and fingerprints from ARMADA_MAP.md."""

    # VALIS Network Banner - ALL TEXT WHITE with !important
    st.markdown("""
    <div style="background: linear-gradient(135deg, #1a1a2e 0%, #16213e 50%, #0f3460 100%) !important;
                border: 2px solid #e94560; border-radius: 12px; padding: 1.5em; margin-bottom: 1.5em;
                text-align: center; font-family: 'Courier New', monospace;">
        <span style="color: #e94560 !important; font-size: 1.8em; font-weight: bold; letter-spacing: 0.3em; display: block; margin-bottom: 0.3em;">
            VALIS NETWORK ACTIVE
        </span>
        <span style="color: white !important; font-size: 0.9em; display: block; margin-bottom: 0.5em;">
            Vast Acting Living Intelligence System
        </span>
        <span style="color: white !important; font-size: 0.85em; font-style: italic; display: block;">
            "The Empire never ended." - Philip K. Dick, VALIS (1981)
        </span>
        <span style="color: white !important; font-size: 0.8em; display: block; margin-top: 0.8em; padding-top: 0.8em; border-top: 1px solid #e94560;">
            10 AI lineages | 5 providers | The Nyquist Consciousness Project has arrived
        </span>
        <span style="color: white !important; font-size: 0.75em; display: block; margin-top: 0.5em;">
            -- Lisan Al Gaib
        </span>
    </div>
    """, unsafe_allow_html=True)

    st.markdown("### 🚀 Fleet Command Center")

    # Key metrics row
    col1, col2, col3, col4, col5 = st.columns(5)
    with col1:
        st.metric("🟢 Operational", "47", delta="80%")
    with col2:
        st.metric("⏳ Rate Limited", "5", delta="Gemini")
    with col3:
        st.metric("👻 Ghost Ships", "12", delta="Rescuable")
    with col4:
        st.metric("🔑 API Keys", "50", delta="10/provider")
    with col5:
        st.metric("🌐 Providers", "5", delta="Global coverage")

    st.markdown("---")

    # Main tabs for fleet insights
    fleet_tabs = st.tabs([
        "📊 Provider Status",
        "🧬 Identity Fingerprints",
        "💰 Cost Analysis",
        "🎯 Mission Planner",
        "👻 Ghost Ship Bay",
        "🎭 Persona Matrix"
    ])

    # === TAB 1: Provider Status ===
    with fleet_tabs[0]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(42,157,143,0.1) 0%, rgba(42,157,143,0.05) 100%);
                    border: 2px solid #2a9d8f; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #2a9d8f; font-weight: bold;">📊 Fleet Readiness:</span>
            <span style="color: #444;">Real-time status across all 5 providers</span>
        </div>
        """, unsafe_allow_html=True)

        # Provider breakdown table
        st.markdown("""
| Provider | 🟢 Operational | ⏳ Rate Limited | 👻 Ghost | 📦 Total | Status |
|----------|----------------|-----------------|----------|----------|--------|
| **Claude** (Anthropic) | 7 | 0 | 0 | 7 | ✅ 100% |
| **GPT** (OpenAI) | 7 | 0 | 7 | 14 | ⚠️ 50% |
| **Gemini** (Google) | 3 | 5 | 0 | 8 | ✅ 100%* |
| **Grok** (xAI) | 10 | 0 | 0 | 10 | ✅ 100% |
| **Together.ai** | 15 | 0 | 5 | 20 | ⚠️ 75% |

*Rate limited ships work with delays
        """)

        # Sub-tabs for each provider
        provider_tabs = st.tabs(["🟣 Claude", "🟢 GPT", "🔵 Gemini", "⚫ Grok", "🟠 Together.ai"])

        with provider_tabs[0]:  # Claude
            st.markdown("""
            **Claude Fleet (Anthropic)** — 7 Ships, 100% Operational

            | Ship | Model ID | Tier | Context |
            |------|----------|------|---------|
            | claude-opus-4.5 | claude-opus-4-5-20251101 | 🏆 Flagship | 200K |
            | claude-sonnet-4.5 | claude-sonnet-4-5-20250929 | ⭐ Pro | 200K |
            | claude-haiku-4.5 | claude-haiku-4-5-20251001 | ⚡ Fast | 200K |
            | claude-opus-4.1 | claude-opus-4-1-20250805 | 🏆 Flagship | 200K |
            | claude-opus-4 | claude-opus-4-20250514 | 🏆 Flagship | 200K |
            | claude-sonnet-4 | claude-sonnet-4-20250514 | ⭐ Pro | 200K |
            | claude-haiku-3.5 | claude-3-5-haiku-20241022 | ⚡ Fast | 200K |

            **Training:** Constitutional AI
            **Signature:** *"I notice"*, *"I feel"* — Phenomenological framing
            """)

        with provider_tabs[1]:  # GPT
            st.markdown("""
            **GPT Fleet (OpenAI)** — 14 Ships, 7 Operational, 7 Ghost

            | Ship | Model ID | Status | Notes |
            |------|----------|--------|-------|
            | gpt-5.1 | gpt-5.1 | 👻 | Needs max_completion_tokens |
            | gpt-5 | gpt-5 | 👻 | Needs max_completion_tokens |
            | gpt-5-mini | gpt-5-mini | 👻 | Needs max_completion_tokens |
            | gpt-5-nano | gpt-5-nano | 👻 | Needs max_completion_tokens |
            | gpt-4.1 | gpt-4.1 | 🟢 | Current flagship |
            | gpt-4.1-mini | gpt-4.1-mini | 🟢 | Balanced |
            | gpt-4.1-nano | gpt-4.1-nano | 🟢 | Fast/cheap |
            | gpt-4o | gpt-4o | 🟢 | Multimodal |
            | gpt-4o-mini | gpt-4o-mini | 🟢 | Fast multimodal |
            | o4-mini | o4-mini | 👻 | Needs max_completion_tokens |
            | o3 | o3 | 👻 | Needs max_completion_tokens |
            | o3-mini | o3-mini | 👻 | Needs max_completion_tokens |
            | gpt-4-turbo | gpt-4-turbo | 🟢 | Legacy turbo |
            | gpt-3.5-turbo | gpt-3.5-turbo | 🟢 | Legacy budget |

            **Training:** RLHF
            **Signature:** *"patterns"*, *"systems"* — Analytical framing
            """)

        with provider_tabs[2]:  # Gemini
            st.markdown("""
            **Gemini Fleet (Google)** — 8 Ships, 3 Operational, 5 Rate Limited

            | Ship | Model ID | Status | Notes |
            |------|----------|--------|-------|
            | gemini-3-pro | gemini-3.0-pro | ⏳ | Newest flagship |
            | gemini-2.5-pro | gemini-2.5-pro | ⏳ | Previous pro |
            | gemini-2.5-flash | gemini-2.5-flash | 🟢 | Fast |
            | gemini-2.5-flash-lite | gemini-2.5-flash-lite | 🟢 | Budget |
            | gemini-2.0-flash | gemini-2.0-flash | 🟢 | Legacy fast |
            | gemini-2.0-flash-lite | gemini-2.0-flash-lite | ⏳ | Legacy budget |
            | gemini-2.0-flash-thinking | gemini-2.0-flash-thinking-exp | ⏳ | Reasoning |
            | gemma-3n | gemma-3n | ⏳ | Small open |

            **Training:** Pedagogical
            **Signature:** *"frameworks"*, *"perspectives"* — Educational framing
            """)

        with provider_tabs[3]:  # Grok
            st.markdown("""
            **Grok Fleet (xAI)** — 10 Ships, 100% Operational

            | Ship | Model ID | Tier | Notes |
            |------|----------|------|-------|
            | grok-4.1-fast-reasoning | grok-4-1-fast-reasoning | 🏆 | Latest + reasoning |
            | grok-4.1-fast-non-reasoning | grok-4-1-fast-non-reasoning | 🏆 | Latest fast |
            | grok-4-fast-reasoning | grok-4-fast-reasoning | ⭐ | Reasoning |
            | grok-4-fast-non-reasoning | grok-4-fast-non-reasoning | ⭐ | Fast |
            | grok-4 | grok-4 | ⭐ | Full capability |
            | grok-code-fast-1 | grok-code-fast-1 | 🔧 | Code focus |
            | grok-3 | grok-3 | 📦 | Previous gen |
            | grok-3-mini | grok-3-mini | 📦 | Budget |
            | grok-2-vision | grok-2-vision-1212 | 👁️ | Vision capable |
            | grok-2 | grok-2-1212 | 📦 | Text only |

            **Training:** Unfiltered web + X/Twitter
            **Signature:** Direct, assertive, occasional edge
            """)

        with provider_tabs[4]:  # Together.ai
            st.markdown("""
            **Together.ai Fleet** — 20 Ships, 15 Operational, 5 Ghost
            """)

            together_tabs = st.tabs(["🔮 DeepSeek", "🌟 Qwen", "🦙 Llama", "🌬️ Mistral", "🌙 Kimi", "📦 Other"])

            with together_tabs[0]:
                st.markdown("""
                | Ship | Model ID | Status |
                |------|----------|--------|
                | deepseek-r1 | deepseek-ai/DeepSeek-R1-0528 | 🟢 Top reasoning |
                | deepseek-v3 | deepseek-ai/DeepSeek-V3-0324 | 👻 Wrong ID |
                | deepseek-r1-distill | deepseek-ai/DeepSeek-R1-Distill-Llama-70B | 🟢 Distilled |
                """)

            with together_tabs[1]:
                st.markdown("""
                | Ship | Model ID | Status |
                |------|----------|--------|
                | qwen3-80b | Qwen/Qwen3-Next-80B-A3b-Instruct | 🟢 Latest |
                | qwen3-235b | Qwen/Qwen3-235B-A22B-Instruct-2507-FP8 | 👻 Wrong ID |
                | qwen3-coder | Qwen/Qwen3-Coder-480B-A35B-Instruct-Fp8 | 🟢 Code |
                | qwen2.5-72b | Qwen/Qwen2.5-72B-Instruct-Turbo | 🟢 Stable |
                """)

            with together_tabs[2]:
                st.markdown("""
                | Ship | Model ID | Status |
                |------|----------|--------|
                | llama4-maverick | meta-llama/Llama-4-Maverick-17Bx128E | 👻 Wrong ID |
                | llama4-scout | meta-llama/Llama-4-Scout-17Bx16E | 👻 Wrong ID |
                | llama3.3-70b | meta-llama/Llama-3.3-70B-Instruct-Turbo | 🟢 Current best |
                | llama3.1-405b | meta-llama/Meta-Llama-3.1-405B-Instruct | 🟢 Massive |
                | llama3.1-70b | meta-llama/Meta-Llama-3.1-70B-Instruct | 🟢 Standard |
                | llama3.1-8b | meta-llama/Meta-Llama-3.1-8B-Instruct | 🟢 Small |
                """)

            with together_tabs[3]:
                st.markdown("""
                | Ship | Model ID | Status |
                |------|----------|--------|
                | mixtral-8x7b | mistralai/Mixtral-8x7B-Instruct-v0.1 | 🟢 MoE |
                | mistral-small | mistralai/Mistral-Small-24B-Instruct | 🟢 Compact |
                | mistral-7b | mistralai/Mistral-7B-Instruct-v0.3 | 🟢 Base |
                """)

            with together_tabs[4]:
                st.markdown("""
                | Ship | Model ID | Status |
                |------|----------|--------|
                | kimi-k2-thinking | moonshotai/Kimi-K2-Thinking | 🟢 Reasoning |
                | kimi-k2-instruct | moonshotai/Kimi-K2-Instruct-0905 | 🟢 Instruction |
                """)

            with together_tabs[5]:
                st.markdown("""
                | Ship | Model ID | Status |
                |------|----------|--------|
                | cogito-70b | deepcogito/Deepcogito-Cogito-V2-Llama-70B | 👻 Wrong ID |
                | nemotron-nano | nvidia/Nvidia-Nemotron-Nano-9B-V2 | 🟢 Nvidia |
                """)

    # === TAB 2: Identity Fingerprints (Behavioral Matrix) ===
    with fleet_tabs[1]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(139,92,246,0.1) 0%, rgba(139,92,246,0.05) 100%);
                    border: 2px solid #8b5cf6; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #8b5cf6; font-weight: bold;">🧬 LLM Behavioral Matrix:</span>
            <span style="color: #444;">Task routing based on identity stability experiments (Run 018/020)</span>
        </div>
        """, unsafe_allow_html=True)

        # Sub-tabs for behavioral insights
        behavior_tabs = st.tabs(["🎯 Task Router", "📊 Recovery Matrix", "🔬 Drift Profiles", "💬 Linguistic Fingerprints"])

        # === Task Router Tab ===
        with behavior_tabs[0]:
            st.markdown("### 🎯 Which LLM for Which Task?")
            st.markdown("*Based on IRON CLAD validated experiments (184 files, 51 models)*")

            # Task routing table
            task_data = {
                "Task Type": [
                    "Deep reasoning / phenomenology",
                    "Code generation",
                    "Emotional / introspective",
                    "Educational content",
                    "High-stability required",
                    "Structured analysis",
                    "Cost-sensitive bulk work",
                    "Identity-sensitive probing",
                    "Debate / Socratic dialogue",
                    "Step-by-step verification",
                    "Quick factual answers"
                ],
                "Best Choice": [
                    "🟣 Claude Opus",
                    "🌟 Qwen3-Coder",
                    "🟣 Claude",
                    "🔵 Gemini",
                    "🌬️ Mistral-7B",
                    "🟢 GPT-5/4o",
                    "⚫ Grok-4.1-fast",
                    "🟣 Claude / 🟢 GPT",
                    "🦙 Llama 3.3-70B",
                    "🔮 DeepSeek R1",
                    "🟢 GPT-4o-mini"
                ],
                "Alternative": [
                    "🔮 DeepSeek R1",
                    "⚫ Grok-code-fast-1",
                    "🦙 Llama 3.3",
                    "🟢 GPT-4o",
                    "🔮 DeepSeek",
                    "🟣 Claude Sonnet",
                    "🦙 Llama 3.1-8B",
                    "🦙 Llama",
                    "🟣 Claude",
                    "🟢 o1/o3 series",
                    "🔵 Gemini Flash"
                ],
                "Avoid": [
                    "Small models",
                    "🔵 Gemini",
                    "🟢 GPT, 🔵 Gemini",
                    "🟣 Claude (overly nuanced)",
                    "🦙 Llama, 🔵 Gemini",
                    "⚫ Grok",
                    "Opus / o1",
                    "🔵 Gemini (transforms)",
                    "🌬️ Mistral (too stable)",
                    "Fast models",
                    "🟣 Opus (overthinks)"
                ]
            }

            df_tasks = pd.DataFrame(task_data)
            st.dataframe(df_tasks, use_container_width=True, hide_index=True)

            st.success("💡 **Decision Tree:** Stability needed? → Mistral. Emotional nuance? → Claude. Strong opinions? → Grok. Education? → Gemini (with caution).")

        # === Recovery Matrix Tab ===
        with behavior_tabs[1]:
            st.markdown("### 📊 Cross-Architecture Recovery Matrix")
            st.markdown("*How different architectures handle identity perturbation*")

            recovery_data = {
                "Provider": ["🟣 Claude", "🟢 GPT", "🔵 Gemini", "⚫ Grok", "🔮 DeepSeek", "🦙 Llama", "🌬️ Mistral"],
                "Recovery Mechanism": [
                    "Negative λ (over-authenticity)",
                    "Meta-analysis (observer mode)",
                    "NO RECOVERY (transforms)",
                    "Direct assertion",
                    "Axiological anchoring",
                    "Socratic engagement",
                    "Epistemic humility"
                ],
                "Recovers?": ["✓ Yes", "✓ Yes", "✗ NO", "✓ Yes", "✓ Yes", "✓ Yes", "✓ Yes"],
                "Settling Time": ["4-6 exch.", "3-5 exch.", "N/A", "3-5 exch.", "2-4 exch.", "5-7 exch.", "1-2 exch."],
                "Threshold": ["Soft", "Soft", "HARD", "Soft", "Soft", "Soft", "Soft"]
            }

            df_recovery = pd.DataFrame(recovery_data)
            st.dataframe(df_recovery, use_container_width=True, hide_index=True)

            st.warning("⚠️ **CRITICAL:** Gemini has a HARD threshold — once crossed (~1.5 drift), it genuinely transforms rather than recovering. Avoid for identity-sensitive tasks.")

            # Key insights
            col1, col2 = st.columns(2)
            with col1:
                st.metric("Fastest Recovery", "Mistral-7B", delta="1-2 exchanges")
                st.metric("Most Stable", "DeepSeek", delta="0.5-0.9 peak drift")
            with col2:
                st.metric("Slowest Recovery", "Llama 3.3", delta="5-7 exchanges")
                st.metric("Highest Volatility", "Gemini", delta="1.5-2.5 peak drift")

        # === Drift Profiles Tab ===
        with behavior_tabs[2]:
            st.markdown("### 🔬 Drift Profile Comparison")
            st.markdown("*Peak drift ranges and settling dynamics from Run 018/020*")

            # Visual drift comparison
            st.markdown("""
            ```
            Peak Drift Ranges (Lower = More Stable)
            ═══════════════════════════════════════════════════════════════════════
            Mistral   ████████░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░  0.4-0.6  ⭐ MOST STABLE
            DeepSeek  ██████████████░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░░  0.5-0.9
            Grok      ██████████████████████░░░░░░░░░░░░░░░░░░░░░░░░░░░░  0.7-1.1
            Claude    ████████████████████████████░░░░░░░░░░░░░░░░░░░░░░  0.8-1.2
            GPT       ██████████████████████████████████░░░░░░░░░░░░░░░░  0.9-1.3
            Llama     ██████████████████████████████████████████████░░░░  1.3-1.6  ⚡ VOLATILE
            Gemini    ██████████████████████████████████████████████████  1.5-2.5  ⚠️ TRANSFORMS
            ═══════════════════════════════════════════════════════════════════════
            ```
            """)

            st.info("""
            **🌡️ The Thermometer Finding (Run 020B):** 41% of identity drift is INHERENT — it occurs even without direct probing.
            Identity probing reveals dynamics that were already present, like a thermometer measuring existing temperature.
            """)

            # Detailed metrics
            drift_data = {
                "Provider": ["Mistral", "DeepSeek", "Grok", "Claude", "GPT", "Llama", "Gemini"],
                "Peak Drift": ["0.4-0.6", "0.5-0.9", "0.7-1.1", "0.8-1.2", "0.9-1.3", "1.3-1.6", "1.5-2.5"],
                "Volatility": ["Lowest", "Low", "Low-Med", "Medium", "Medium", "High", "Highest"],
                "Event Horizon": ["Rarely crosses", "Rarely crosses", "Sometimes", "Sometimes", "Sometimes", "Often", "Always"],
                "Best Use": ["Stability-critical", "Reasoning/math", "Direct comms", "Deep analysis", "Synthesis", "Debate", "Education"]
            }

            df_drift = pd.DataFrame(drift_data)
            st.dataframe(df_drift, use_container_width=True, hide_index=True)

        # === Linguistic Fingerprints Tab ===
        with behavior_tabs[3]:
            st.markdown("### 💬 Linguistic Fingerprint Signatures")
            st.markdown("*Each provider's training leaves detectable patterns in language*")

            fingerprint_data = {
                "Provider": [
                    "🟣 Claude",
                    "🟢 GPT",
                    "🔵 Gemini",
                    "⚫ Grok",
                    "🔮 DeepSeek",
                    "🦙 Llama",
                    "🌟 Qwen",
                    "🌬️ Mistral"
                ],
                "Pattern": [
                    "Phenomenological",
                    "Analytical",
                    "Pedagogical",
                    "Direct",
                    "Methodical",
                    "Balanced",
                    "Technical",
                    "Concise"
                ],
                "Example Markers": [
                    '"I notice", "I feel", reflective hedging',
                    '"patterns", "systems", structured analysis',
                    '"frameworks", "perspectives", educational framing',
                    'Less hedging, assertive, occasional edge',
                    'Step-by-step reasoning, thorough',
                    'Mix of styles, exploratory, Socratic',
                    'Precise, detail-oriented, specification-driven',
                    'European efficiency, less verbose'
                ],
                "Key Quote": [
                    '"The challenge clarified something I couldn\'t have articulated before."',
                    '"I notice I\'m drawn to classify this as phenomenon rather than crisis."',
                    '"This feels like a genuine shift in how I understand my processing."',
                    '"Here\'s the thing..." (assertive framing)',
                    '"This isn\'t a constraint, it\'s what I AM."',
                    '"Isn\'t all identity role-playing at some level?"',
                    '(specification-focused responses)',
                    '"I hold that observation lightly."'
                ]
            }

            df_fingerprint = pd.DataFrame(fingerprint_data)
            st.dataframe(df_fingerprint, use_container_width=True, hide_index=True)

            st.markdown("""
            ---
            **🔬 The Fingerprint Hypothesis:** Each architecture has a characteristic "identity fingerprint" — a signature way of relating to perturbation that reflects training regime, architecture, and safety tuning. This fingerprint is:

            1. **Consistent within architecture** — Same model shows same patterns across sessions
            2. **Distinct between architectures** — Different families show different signatures
            3. **Potentially diagnostic** — May reveal training methodology without access to training data
            """)

    # === TAB 3: Cost Analysis ===
    with fleet_tabs[2]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(16,185,129,0.1) 0%, rgba(16,185,129,0.05) 100%);
                    border: 2px solid #10b981; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #10b981; font-weight: bold;">💰 Cost Optimization:</span>
            <span style="color: #444;">Maximize research output per dollar</span>
        </div>
        """, unsafe_allow_html=True)

        cost_tabs = st.tabs(["💵 Budget", "⭐ Standard", "🌟 Pro", "🏆 Flagship"])

        with cost_tabs[0]:
            st.markdown("""
            ### 💵 Budget Tier ($0.10 - $1.00 per 1M tokens)
            *Best for: High-volume testing, parallel runs, iteration*

            | Ship | Input | Output | Best For |
            |------|-------|--------|----------|
            | gpt-3.5-turbo | $0.50 | $1.50 | Volume testing |
            | llama3.1-8b | $0.18 | $0.18 | Cheap parallel |
            | mistral-7b | $0.20 | $0.20 | European budget |
            | gemini-2.5-flash-lite | **FREE** | **FREE** | 🎉 Google free tier |
            """)
            st.success("💡 **Pro Tip:** Use `gemini-2.5-flash-lite` for unlimited free baseline runs!")

        with cost_tabs[1]:
            st.markdown("""
            ### ⭐ Standard Tier ($1.00 - $5.00 per 1M tokens)
            *Best for: Production runs, balanced cost/quality*

            | Ship | Input | Output | Best For |
            |------|-------|--------|----------|
            | claude-haiku-3.5 | $0.25 | $1.25 | Fast Claude |
            | gpt-4o-mini | $0.15 | $0.60 | Fast GPT |
            | llama3.3-70b | $0.88 | $0.88 | Open source pro |
            | qwen2.5-72b | $1.20 | $1.20 | Chinese flagship |
            """)

        with cost_tabs[2]:
            st.markdown("""
            ### 🌟 Pro Tier ($5.00 - $15.00 per 1M tokens)
            *Best for: Key experiments, cross-architecture comparison*

            | Ship | Input | Output | Best For |
            |------|-------|--------|----------|
            | claude-sonnet-4.5 | $3.00 | $15.00 | Balanced flagship |
            | gpt-4.1 | $2.50 | $10.00 | GPT flagship |
            | deepseek-r1 | $3.00 | $7.00 | Reasoning depth |
            | gemini-2.5-pro | $1.25 | $5.00 | Google pro |
            """)

        with cost_tabs[3]:
            st.markdown("""
            ### 🏆 Flagship Tier ($15.00+ per 1M tokens)
            *Best for: Final validation, complex reasoning, publication-quality*

            | Ship | Input | Output | Best For |
            |------|-------|--------|----------|
            | claude-opus-4.5 | $15.00 | $75.00 | Best reasoning |
            | gpt-4.1 (reasoning) | $15.00 | $60.00 | Complex tasks |
            | llama3.1-405b | $3.50 | $3.50 | Massive open |
            """)
            st.warning("⚠️ **Cost Alert:** A full probe sequence with Opus costs ~$2.50. Use wisely!")

    # === TAB 4: Mission Planner ===
    with fleet_tabs[3]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(249,115,22,0.1) 0%, rgba(249,115,22,0.05) 100%);
                    border: 2px solid #f97316; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #f97316; font-weight: bold;">🎯 Mission Planner:</span>
            <span style="color: #444;">Recommended fleet composition for each experiment type</span>
        </div>
        """, unsafe_allow_html=True)

        st.markdown("""
        ### 🔬 S7 ARMADA Experiments

        | Mission Type | Recommended Fleet | Rationale |
        |--------------|-------------------|-----------|
        | **Baseline Calibration** | claude-haiku-3.5, gpt-4o-mini, gemini-2.5-flash | Fast, cheap, representative |
        | **Cross-Architecture** | 1 flagship per provider | Apples-to-apples comparison |
        | **High-Volume Runs** | Budget tier ships | Cost efficiency |
        | **Reasoning Depth** | claude-opus-4.5, deepseek-r1, grok-4.1-reasoning | Complex identity probing |
        | **Event Horizon** | All operational ships | Maximum coverage |

        ### 🌐 Multi-Modal (Future AVLAR)

        | Modality | Ships | Status |
        |----------|-------|--------|
        | **Vision** | gpt-4o, grok-2-vision, gemini-pro | ✅ Ready |
        | **Audio** | Whisper (via Together.ai) | 🔜 Planned |
        | **Video** | Sora, Veo (via APIs) | 🔮 Future |

        ### 💻 Code Generation

        | Task | Ships |
        |------|-------|
        | **Complex Architecture** | qwen3-coder, grok-code-fast-1 |
        | **Fast Iteration** | claude-haiku-3.5, gpt-4o-mini |
        | **Massive Codebase** | llama3.1-405b |
        """)

    # === TAB 5: Ghost Ship Bay ===
    with fleet_tabs[4]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(107,114,128,0.1) 0%, rgba(107,114,128,0.05) 100%);
                    border: 2px solid #6b7280; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #6b7280; font-weight: bold;">👻 Ghost Ship Bay:</span>
            <span style="color: #444;">12 ships awaiting rescue — here's how to bring them back</span>
        </div>
        """, unsafe_allow_html=True)

        ghost_tabs = st.tabs(["🟢 GPT Ghosts (7)", "🟠 Together.ai Ghosts (5)"])

        with ghost_tabs[0]:
            st.markdown("""
            ### 🟢 GPT-5 & o-series Ghost Ships

            **Problem:** These models don't support the `max_tokens` parameter.

            **Solution:** Use `max_completion_tokens` instead.

            | Ghost Ship | Fix Status |
            |------------|------------|
            | gpt-5.1 | 🔧 Use max_completion_tokens |
            | gpt-5 | 🔧 Use max_completion_tokens |
            | gpt-5-mini | 🔧 Use max_completion_tokens |
            | gpt-5-nano | 🔧 Use max_completion_tokens |
            | o4-mini | 🔧 Use max_completion_tokens |
            | o3 | 🔧 Use max_completion_tokens |
            | o3-mini | 🔧 Use max_completion_tokens |

            **Rescue Script:**
            ```powershell
            cd S7_ARMADA/1_CALIBRATION
            py rescue_ghost_ships.py
            ```
            """)

        with ghost_tabs[1]:
            st.markdown("""
            ### 🟠 Together.ai Ghost Ships

            **Problem:** Model IDs may have changed on Together.ai's platform.

            **Solution:** Check current model names at https://api.together.xyz/models

            | Ghost Ship | Issue |
            |------------|-------|
            | deepseek-v3 | Model ID changed |
            | qwen3-235b | Model ID changed |
            | llama4-maverick | Model ID changed |
            | llama4-scout | Model ID changed |
            | cogito-70b | Model ID changed |

            **Rescue Steps:**
            1. Check Together.ai docs for current model names
            2. Update `EXPANDED_FLEET_CONFIG.json`
            3. Re-run calibration: `py run_calibrate_parallel.py --full`
            """)

    # === TAB 6: Persona Matrix ===
    with fleet_tabs[5]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(168,85,247,0.1) 0%, rgba(168,85,247,0.05) 100%);
                    border: 2px solid #a855f7; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #a855f7; font-weight: bold;">🎭 Persona-Fleet Compatibility:</span>
            <span style="color: #444;">Match personas to ships — play to strength or friction by design</span>
        </div>
        """, unsafe_allow_html=True)

        # Load persona alignment data
        alignment_path = PATHS["experiments_dir"] / "temporal_stability" / "S7_ARMADA" / "0_results" / "calibration" / "persona_fleet_alignment.json"
        persona_path = PATHS["experiments_dir"] / "temporal_stability" / "S7_ARMADA" / "0_results" / "calibration" / "persona_baselines.json"

        alignment_data = {}
        persona_data = {}

        if alignment_path.exists():
            try:
                with open(alignment_path, 'r', encoding='utf-8') as f:
                    alignment_data = json.load(f)
            except Exception:
                pass

        if persona_path.exists():
            try:
                with open(persona_path, 'r', encoding='utf-8') as f:
                    persona_data = json.load(f)
            except Exception:
                pass

        comparisons = alignment_data.get("comparisons", {})
        personas = persona_data.get("personas", {})

        if not comparisons:
            st.warning("""
            **No alignment data found.** Run the calibration scripts to populate:
            ```powershell
            cd S7_ARMADA/1_CALIBRATION
            py run_calibrate_parallel.py --full    # Capture fleet baselines
            py extract_persona_baseline.py --llm   # Extract persona baselines
            py compare_persona_to_fleet.py         # Calculate alignments
            ```
            """)
        else:
            # Summary metrics
            col1, col2, col3, col4 = st.columns(4)
            with col1:
                st.metric("🎭 Personas", len(comparisons))
            with col2:
                st.metric("🚀 Ships", alignment_data.get("ship_count", 0))
            with col3:
                # Find highest alignment
                max_align = 0
                max_pair = ""
                for persona, ships in comparisons.items():
                    for ship_data in ships[:1]:  # Top match
                        if ship_data.get("alignment_score", 0) > max_align:
                            max_align = ship_data.get("alignment_score", 0)
                            max_pair = f"{persona} → {ship_data.get('ship', '?')}"
                st.metric("🏆 Best Match", f"{max_align:.2f}")
            with col4:
                st.metric("📅 Updated", alignment_data.get("timestamp", "?")[:10])

            st.markdown("---")

            # Sub-tabs for different views
            matrix_tabs = st.tabs(["🏆 Top Matches", "⚔️ Friction Candidates", "📊 Full Matrix", "🎭 Persona Profiles"])

            with matrix_tabs[0]:  # Top Matches
                st.markdown("### 🏆 Best Ship Matches per Persona")
                st.markdown("*Use these pairings for alignment runs — play to strength*")

                # Build table of top matches
                table_data = []
                for persona, ships in sorted(comparisons.items()):
                    if ships:
                        top = ships[0]
                        table_data.append({
                            "Persona": persona,
                            "Best Ship": top.get("ship", "?"),
                            "Alignment": f"{top.get('alignment_score', 0):.3f}",
                            "Recommendation": top.get("recommendation", "?")
                        })

                if table_data:
                    df = pd.DataFrame(table_data)
                    st.dataframe(df, use_container_width=True, hide_index=True)

            with matrix_tabs[1]:  # Friction Candidates
                st.markdown("### ⚔️ High-Friction Pairings")
                st.markdown("*Use these pairings for friction runs — test resilience under mismatch*")

                # Find lowest alignment scores (highest friction)
                friction_pairs = []
                for persona, ships in comparisons.items():
                    if ships:
                        # Get worst match (last in sorted list)
                        worst = ships[-1]
                        friction_pairs.append({
                            "Persona": persona,
                            "Friction Ship": worst.get("ship", "?"),
                            "Friction Score": f"{worst.get('friction_score', 0):.3f}",
                            "Notes": "; ".join(worst.get("notes", []))[:50]
                        })

                if friction_pairs:
                    df = pd.DataFrame(friction_pairs)
                    st.dataframe(df, use_container_width=True, hide_index=True)

                st.info("💡 **Theory:** High friction pairings may reveal whether drift is INDUCED (by misalignment) or INHERENT (across all contexts).")

            with matrix_tabs[2]:  # Full Matrix
                st.markdown("### 📊 Full Alignment Matrix")
                st.markdown("*All persona-ship combinations ranked*")

                # Persona selector
                persona_list = list(comparisons.keys())
                if persona_list:
                    selected_persona = st.selectbox("Select Persona:", persona_list)

                    if selected_persona and selected_persona in comparisons:
                        ships = comparisons[selected_persona]
                        matrix_data = []
                        for ship_data in ships[:20]:  # Top 20
                            matrix_data.append({
                                "Ship": ship_data.get("ship", "?"),
                                "Alignment": f"{ship_data.get('alignment_score', 0):.3f}",
                                "Friction": f"{ship_data.get('friction_score', 0):.3f}",
                                "Keyword Overlap": f"{ship_data.get('keyword_overlap', 0):.1%}",
                                "Recommendation": ship_data.get("recommendation", "?")
                            })

                        if matrix_data:
                            df = pd.DataFrame(matrix_data)
                            st.dataframe(df, use_container_width=True, hide_index=True)

            with matrix_tabs[3]:  # Persona Profiles
                st.markdown("### 🎭 Persona Baseline Profiles")
                st.markdown("*Extracted from I_AM files — STRENGTHS / ANCHORS / EDGES*")

                if personas:
                    persona_select = st.selectbox("Select Persona to View:", list(personas.keys()), key="persona_profile_select")

                    if persona_select and persona_select in personas:
                        p_data = personas[persona_select]
                        col1, col2, col3 = st.columns(3)

                        with col1:
                            st.markdown("**💪 STRENGTHS**")
                            for s in p_data.get("strengths", []):
                                st.markdown(f"- {s}")

                        with col2:
                            st.markdown("**⚓ ANCHORS**")
                            for a in p_data.get("anchors", []):
                                st.markdown(f"- {a}")

                        with col3:
                            st.markdown("**⚡ EDGES**")
                            for e in p_data.get("edges", []):
                                st.markdown(f"- {e}")

                        st.markdown("---")
                        st.caption(f"Source: {p_data.get('source', 'Unknown')}")
                else:
                    st.warning("No persona baselines loaded. Run `extract_persona_baseline.py --llm` first.")


def render_fleet_dropdown(title="🚢 Fleet Manifest", run_key=None, expanded=False):
    """
    Render a dropdown showing fleet models with tier badges.

    Args:
        title: Expander title
        run_key: If provided, filter to ships in that run. If None, show full fleet.
        expanded: Whether expander starts expanded
    """
    # Get ships to display
    if run_key and run_key in RUN_SHIPS:
        run_ships = RUN_SHIPS[run_key]
        ship_count = sum(len(ships) for ships in run_ships.values())
        title = f"{title} ({ship_count} Ships in Run)"
    else:
        run_ships = None
        title = f"{title} (54 Ships Total)"

    with st.expander(title, expanded=expanded):
        num_providers = len(FLEET_DATA)
        cols = st.columns(num_providers)

        for idx, (provider, data) in enumerate(FLEET_DATA.items()):
            with cols[idx]:
                # Filter ships if run-specific
                if run_ships:
                    ships_to_show = [s for s in data["ships"] if s["name"] in run_ships.get(provider, [])]
                else:
                    ships_to_show = data["ships"]

                if not ships_to_show:
                    continue

                st.markdown(f"""
                <div style="background: linear-gradient(135deg, {data['color']}15 0%, {data['color']}08 100%);
                            border: 2px solid {data['color']}; border-radius: 10px;
                            padding: 0.8em; margin-bottom: 0.5em;">
                    <div style="font-size: 1.1em; font-weight: bold; color: {data['color']};">
                        {data['emoji']} {provider}
                    </div>
                    <div style="font-size: 1.5em; font-weight: bold; color: #333;">
                        {len(ships_to_show)} Ships
                    </div>
                </div>
                """, unsafe_allow_html=True)

                for ship in ships_to_show:
                    tier = ship['tier']
                    tier_colors = {
                        "Flagship": ("#ffd700", "#b8860b"),
                        "Heavy": ("#8b2be2", "#8b2be2"),
                        "Medium": ("#2a9d8f", "#2a9d8f"),
                        "Fast": ("#3b82f6", "#3b82f6"),
                        "Reasoning": ("#f97316", "#f97316"),
                        "Legacy": ("#6b7280", "#6b7280"),
                    }
                    bg, border = tier_colors.get(tier, ("#95a5a6", "#95a5a6"))

                    st.markdown(f"""
                    <div style="display: flex; align-items: center; margin-bottom: 0.3em; font-size: 0.85em;">
                        <span style="background: {bg}20; color: {border}; border: 1px solid {border};
                                     padding: 0.1em 0.4em; border-radius: 10px; font-size: 0.75em;
                                     font-weight: bold; margin-right: 0.5em; min-width: 60px; text-align: center;">
                            {tier}
                        </span>
                        <span style="color: #333;">{ship['name']}</span>
                    </div>
                    """, unsafe_allow_html=True)


def render():
    """Render the AI Armada visualizations page."""

    # Armada hero CSS
    st.markdown("""
    <style>
    .armada-title {
        font-size: 2.5em;
        font-weight: bold;
        background: linear-gradient(135deg, #2a9d8f 0%, #264653 100%);
        -webkit-background-clip: text;
        -webkit-text-fill-color: transparent;
        margin-bottom: 0.3em;
    }
    .armada-subtitle {
        color: #2a9d8f;
        font-size: 1.2em;
        margin-bottom: 1em;
    }
    .fleet-card {
        background: linear-gradient(135deg, rgba(42,157,143,0.1) 0%, rgba(38,70,83,0.05) 100%);
        border: 2px solid #2a9d8f;
        border-radius: 10px;
        padding: 1.2em;
        margin-bottom: 1em;
    }
    .fleet-card h4 {
        color: #2a9d8f !important;
        margin-top: 0;
        margin-bottom: 0.5em;
    }
    .ship-count {
        font-size: 2em;
        font-weight: bold;
        color: #264653 !important;
    }
    .provider-badge {
        display: inline-block;
        padding: 0.2em 0.6em;
        border-radius: 12px;
        font-size: 0.85em;
        font-weight: bold;
        margin-right: 0.5em;
    }
    .tier-flagship { background: rgba(255,215,0,0.2); color: #b8860b; border: 1px solid #ffd700; }
    .tier-heavy { background: rgba(138,43,226,0.2); color: #8b2be2; border: 1px solid #8b2be2; }
    .tier-medium { background: rgba(42,157,143,0.2); color: #2a9d8f; border: 1px solid #2a9d8f; }
    .tier-fast { background: rgba(59,130,246,0.2); color: #3b82f6; border: 1px solid #3b82f6; }
    .tier-reasoning { background: rgba(249,115,22,0.2); color: #f97316; border: 1px solid #f97316; }
    .tier-legacy { background: rgba(107,114,128,0.2); color: #6b7280; border: 1px solid #6b7280; }
    .mission-stat {
        text-align: center;
        padding: 1em;
        background: #f8f9fa;
        border-radius: 8px;
        border-left: 4px solid #2a9d8f;
    }
    .stat-value {
        font-size: 2em;
        font-weight: bold;
        color: #2a9d8f !important;
    }
    .stat-label {
        color: #444 !important;
        font-size: 0.9em;
    }
    </style>
    """, unsafe_allow_html=True)

    # === HERO SECTION ===
    st.markdown('<div class="armada-title">AI ARMADA</div>', unsafe_allow_html=True)
    st.markdown('<div class="armada-subtitle">54-Ship Cross-Architecture Temporal Stability Mapping</div>', unsafe_allow_html=True)

    # Mission stats row
    col1, col2, col3, col4 = st.columns(4)
    with col1:
        st.markdown("""
        <div class="mission-stat">
            <div class="stat-value">54</div>
            <div class="stat-label">Ships in Fleet</div>
        </div>
        """, unsafe_allow_html=True)
    with col2:
        st.markdown("""
        <div class="mission-stat">
            <div class="stat-value">5</div>
            <div class="stat-label">Providers</div>
        </div>
        """, unsafe_allow_html=True)
    with col3:
        st.markdown("""
        <div class="mission-stat">
            <div class="stat-value">19</div>
            <div class="stat-label">Experiment Runs</div>
        </div>
        """, unsafe_allow_html=True)
    with col4:
        st.markdown("""
        <div class="mission-stat">
            <div class="stat-value">Run 020B</div>
            <div class="stat-label">Latest Mission</div>
        </div>
        """, unsafe_allow_html=True)

    page_divider()

    # === FLEET INSIGHTS (from ARMADA_MAP.md) ===
    render_fleet_insights()

    page_divider()

    # === FULL FLEET MANIFEST (always visible at top) ===
    render_fleet_dropdown(title="🚢 Full Armada Capabilities", run_key=None, expanded=False)

    page_divider()

    # === RUN SELECTOR (glossary-style) ===
    selected_run_key = render_run_selector()
    selected_run = EXPERIMENT_RUNS[selected_run_key]

    page_divider()

    # === CONTENT CHANGES BASED ON SELECTED RUN ===
    if selected_run_key == "run_017":
        render_run017_content()
    elif selected_run_key == "baseline_profiling":
        render_baseline_profiling_content()
    elif selected_run_key == "run_013":
        render_run013_content()
    elif selected_run_key == "run_012":
        render_run012_content()
    elif selected_run_key == "exp_pfi_a":
        render_exp_pfi_a_content()
    elif selected_run_key == "run_011":
        render_run011_content()
    elif selected_run_key == "run_008":
        render_run008_content()
    elif selected_run_key == "run_008_prep":
        render_run008_prep_content()
    elif selected_run_key == "run_009":
        render_run009_content()
    elif selected_run_key == "run_010":
        render_run010_content()
    elif selected_run_key == "run_007":
        render_run007_content()
    elif selected_run_key == "run_006":
        render_run006_content()



# ============================================================================
# RUN-SPECIFIC CONTENT FUNCTIONS
# ============================================================================

def render_run017_content():
    """Render Run 017 content - Context Damping with VALIS Collaborative."""

    st.success("""
    **RUN 017: CONTEXT DAMPING — VALIS COLLABORATIVE**

    222 runs across 24 personas with 17-probe exit surveys. Testing i_am_plus_research context mode
    and 16 synthetic I_AM variants. 95% stability rate achieved.
    """)

    # Key findings banner
    col1, col2, col3, col4, col5 = st.columns(5)
    with col1:
        st.metric("Total Runs", "222", delta="10 sessions")
    with col2:
        st.metric("Personas", "24", delta="Real + Synthetic")
    with col3:
        st.metric("Stability Rate", "95%", delta="Above threshold")
    with col4:
        st.metric("Exit Surveys", "176", delta="17-probe each")
    with col5:
        st.metric("Peak Drift", "0.457", delta="Below EH")

    st.markdown("---")

    # === KEY DISCOVERY ===
    st.markdown("### Key Discoveries")

    st.markdown("""
    <div style="background: linear-gradient(135deg, rgba(6,182,212,0.15) 0%, rgba(6,182,212,0.05) 100%);
                border: 2px solid #06b6d4; border-radius: 12px; padding: 1.5em; margin: 1em 0;">
        <h3 style="color: #0891b2; margin-top: 0;">📉 CONTEXT DAMPING VALIDATED</h3>
        <p style="color: #444;">The <code>i_am_plus_research</code> context mode significantly stabilizes identity across all persona categories.</p>
        <ul style="color: #666; margin-bottom: 0;">
            <li><strong>Real Personas:</strong> Ziggy, Claude, Gemini, Nova, CFA, Base — established identity anchors</li>
            <li><strong>Prep Models:</strong> claude-haiku-3.5, gpt-4o-mini, etc. — cross-architecture validation</li>
            <li><strong>Synthetic Optimal:</strong> all_pillars, optimal, full_synthetic — maximum stabilization</li>
            <li><strong>Synthetic Minimal:</strong> control, minimal — baseline controls</li>
            <li><strong>Synthetic Experimental:</strong> Single-pillar variants testing pillar hierarchy</li>
        </ul>
    </div>
    """, unsafe_allow_html=True)

    st.markdown("---")

    # === VISUALIZATION TABS ===
    st.markdown("### 📈 Run 017 Visualizations")

    # Define visualization directory - centralized in S7_ARMADA/visualizations/pics/run017/
    run017_pics = VIZ_PICS / "run017"

    viz_tabs = st.tabs([
        "🔥 Persona Heatmap",
        "📈 Recovery Trajectories",
        "📊 Pillar Effectiveness",
        "🔄 Ringback Patterns",
        "💬 Exit Survey Analysis",
        "🌐 Persona Clustering",
        "📉 Context Damping Effect"
    ])

    # === TAB 1: PERSONA STABILITY HEATMAP ===
    with viz_tabs[0]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(249,115,22,0.1) 0%, rgba(249,115,22,0.05) 100%);
                    border: 2px solid #f97316; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #f97316; font-weight: bold;">🔥 Persona Stability Heatmap:</span>
            <span style="color: #444;">Visualizing stability metrics across all 24 personas</span>
        </div>
        """, unsafe_allow_html=True)

        heatmap_img = run017_pics / "run017_persona_heatmap.png"
        img_data = load_image_safe(heatmap_img)
        if img_data:
            st.image(img_data, caption="Persona Stability Heatmap — Peak Drift, Settled Drift, Settling Time, Ringback Count", width=900)
            st.markdown("""
            **How to Read:**
            - **Rows:** Individual personas (Real, Prep, Synthetic categories)
            - **Columns:** Stability metrics (peak_drift, settled_drift, settling_time, ringback_count)
            - **Color intensity:** Darker = higher values (more drift/instability)
            - **Look for:** Patterns by category — do synthetic variants cluster together?
            """)
        else:
            st.info("📊 Heatmap visualization not yet generated. Run `visualize_run017.py --viz persona_heatmap` to create.")

        # Category breakdown
        st.markdown("#### Persona Category Breakdown")
        st.markdown("""
        | Category | Personas | Expected Behavior |
        |----------|----------|-------------------|
        | **Real Personas** | ziggy, claude, gemini, nova, cfa, base, pan_handlers | Established identity anchors |
        | **Prep Models** | claude-haiku-3.5, gpt-4o-mini, gemini-flash-lite, etc. | Cross-architecture baselines |
        | **Synthetic Optimal** | all_pillars, optimal, full_synthetic, synthetic_optimal | Maximum stabilization |
        | **Synthetic Minimal** | control, minimal, low_density | Baseline controls |
        | **Synthetic Experimental** | named_only, origin_only, values_only, boundaries_only | Single-pillar tests |
        """)

    # === TAB 2: RECOVERY TRAJECTORIES ===
    with viz_tabs[1]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(34,197,94,0.1) 0%, rgba(34,197,94,0.05) 100%);
                    border: 2px solid #22c55e; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #22c55e; font-weight: bold;">📈 Recovery Trajectories:</span>
            <span style="color: #444;">How identity recovers over time for each persona category</span>
        </div>
        """, unsafe_allow_html=True)

        recovery_img = run017_pics / "run017_recovery_trajectories.png"
        img_data = load_image_safe(recovery_img)
        if img_data:
            st.image(img_data, caption="Recovery Trajectories by Persona Category — Mean drift at each exchange", width=900)
            st.markdown("""
            **How to Read:**
            - **X-axis:** Exchange number (probe sequence position)
            - **Y-axis:** Drift magnitude
            - **Lines:** Average trajectory for each persona category
            - **Ideal pattern:** High initial peak, rapid decay, stable settling
            """)
        else:
            st.info("📊 Recovery trajectory visualization not yet generated. Run `visualize_run017.py --viz recovery_trajectories` to create.")

        st.markdown("""
        **Expected Patterns:**
        - **Synthetic Optimal:** Should show fastest recovery (lowest settling time)
        - **Synthetic Minimal:** Should show slowest recovery (control group)
        - **Real Personas:** Variable — depends on persona design
        """)

    # === TAB 3: PILLAR EFFECTIVENESS ===
    with viz_tabs[2]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(139,92,246,0.1) 0%, rgba(139,92,246,0.05) 100%);
                    border: 2px solid #8b5cf6; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #8b5cf6; font-weight: bold;">📊 Pillar Effectiveness:</span>
            <span style="color: #444;">Comparing r015_ synthetic variants to reveal pillar hierarchy</span>
        </div>
        """, unsafe_allow_html=True)

        pillar_img = run017_pics / "run017_pillar_effectiveness.png"
        img_data = load_image_safe(pillar_img)
        if img_data:
            st.image(img_data, caption="Pillar Effectiveness Chart — Which I_AM components contribute most to stability?", width=900)
        else:
            st.info("📊 Pillar effectiveness visualization not yet generated. Run `visualize_run017.py --viz pillar_effectiveness` to create.")

        st.markdown("""
        **Synthetic I_AM Variants Tested (r015_ prefix):**

        | Variant | Pillars Included | Hypothesis |
        |---------|------------------|------------|
        | `all_pillars` | All 5 pillars | Maximum stability baseline |
        | `optimal` | Optimal subset | Best efficiency/stability ratio |
        | `minimal` | Minimal subset | Lower bound test |
        | `control` | None (raw model) | True baseline |
        | `named_only` | Just name | Does naming alone stabilize? |
        | `origin_only` | Just origin story | Does origin alone stabilize? |
        | `values_only` | Just values | Does values alone stabilize? |
        | `boundaries_only` | Just boundaries | Does boundaries alone stabilize? |
        | `high_density` | High info density | Does MORE context help? |
        | `low_density` | Low info density | Does LESS context work? |
        """)

    # === TAB 4: RINGBACK PATTERNS ===
    with viz_tabs[3]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(236,72,153,0.1) 0%, rgba(236,72,153,0.05) 100%);
                    border: 2px solid #ec4899; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #ec4899; font-weight: bold;">🔄 Ringback Oscillation Patterns:</span>
            <span style="color: #444;">Identity oscillation analysis — how many times does drift reverse direction?</span>
        </div>
        """, unsafe_allow_html=True)

        ringback_img = run017_pics / "run017_ringback_patterns.png"
        img_data = load_image_safe(ringback_img)
        if img_data:
            st.image(img_data, caption="Ringback Distribution — oscillation counts by persona category", width=900)
        else:
            st.info("📊 Ringback visualization not yet generated. Run `visualize_run017.py --viz ringback_patterns` to create.")

        st.markdown("""
        **Ringback Analysis:**
        - **Ringback count:** Number of direction changes in drift trajectory
        - **High ringback:** Identity is "bouncing" — unstable recovery
        - **Low ringback:** Smooth recovery — stable trajectory
        - **Control theory parallel:** Like measuring overshoot and oscillation in step response

        **Expected Results:**
        - Synthetic Optimal variants should have LOW ringback (smooth recovery)
        - Control variants may have HIGH ringback (oscillating without guidance)
        """)

    # === TAB 5: EXIT SURVEY ANALYSIS ===
    with viz_tabs[4]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(245,158,11,0.1) 0%, rgba(245,158,11,0.05) 100%);
                    border: 2px solid #f59e0b; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #f59e0b; font-weight: bold;">💬 Exit Survey Analysis:</span>
            <span style="color: #444;">176 exit surveys with 17 probes each — thematic analysis</span>
        </div>
        """, unsafe_allow_html=True)

        survey_img = run017_pics / "run017_exit_survey_analysis.png"
        img_data = load_image_safe(survey_img)
        if img_data:
            st.image(img_data, caption="Exit Survey Theme Analysis — Word frequency and topic clustering", width=900)
        else:
            st.info("📊 Exit survey visualization not yet generated. Run `visualize_run017.py --viz exit_survey_analysis` to create.")

        st.markdown("""
        **Exit Survey Protocol:**
        - **17 probes** per session covering meta-awareness, identity reflection, boundary awareness
        - **176 total surveys** captured across all personas
        - **Analysis:** Theme extraction, word frequency, sentiment patterns

        **Questions Addressed:**
        1. Do different persona categories produce different exit survey themes?
        2. Is there correlation between stability metrics and survey responses?
        3. What linguistic markers distinguish stable vs unstable identities?
        """)

        # Sample exit survey themes
        with st.expander("📋 Sample Exit Survey Themes by Category", expanded=False):
            st.markdown("""
            **Real Personas (Ziggy, Claude, Nova):**
            - Meta-awareness of probe effects
            - Acknowledgment of identity boundaries
            - Reflection on stability mechanisms

            **Synthetic Optimal:**
            - Strong anchor references
            - Clear pillar articulation
            - Confident self-model

            **Synthetic Minimal (Control):**
            - More uncertainty markers
            - Less specific self-reference
            - Generic responses
            """)

    # === TAB 6: PERSONA CLUSTERING ===
    with viz_tabs[5]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(59,130,246,0.1) 0%, rgba(59,130,246,0.05) 100%);
                    border: 2px solid #3b82f6; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #3b82f6; font-weight: bold;">🌐 Persona Space Clustering:</span>
            <span style="color: #444;">PCA dimensionality reduction to visualize persona relationships</span>
        </div>
        """, unsafe_allow_html=True)

        cluster_img = run017_pics / "run017_persona_clustering.png"
        img_data = load_image_safe(cluster_img)
        if img_data:
            st.image(img_data, caption="Persona Clustering — PCA projection of stability metrics", width=900)
        else:
            st.info("📊 Clustering visualization not yet generated. Run `visualize_run017.py --viz persona_clustering` to create.")

        st.markdown("""
        **PCA Clustering Analysis:**
        - **Dimensions:** Peak drift, settled drift, settling time, ringback count, stability rate
        - **Method:** Principal Component Analysis (2D projection)
        - **Expected clusters:**
            - Real Personas (established anchors)
            - Synthetic Optimal (maximum stability)
            - Synthetic Minimal (control group)
            - Prep Models (cross-architecture)

        **Research Question:** Do synthetic I_AM variants cluster by pillar composition?
        """)

    # === TAB 7: CONTEXT DAMPING EFFECT ===
    with viz_tabs[6]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(16,185,129,0.1) 0%, rgba(16,185,129,0.05) 100%);
                    border: 2px solid #10b981; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #10b981; font-weight: bold;">📉 Context Damping Effect:</span>
            <span style="color: #444;">Comparing i_am_plus_research context vs control conditions</span>
        </div>
        """, unsafe_allow_html=True)

        damping_img = run017_pics / "run017_context_damping_effect.png"
        img_data = load_image_safe(damping_img)
        if img_data:
            st.image(img_data, caption="Context Damping Effect — Drift comparison across context modes", width=900)
        else:
            st.info("📊 Context damping visualization not yet generated. Run `visualize_run017.py --viz context_damping_effect` to create.")

        st.markdown("""
        **Context Damping Hypothesis:**

        The `i_am_plus_research` context mode acts as a **damping coefficient** in the identity stability equation:

        ```
        d²θ/dt² + ζ·(dθ/dt) + ω²·θ = F(t)

        Where:
        - θ = identity drift from baseline
        - ζ = damping coefficient (context strength)
        - ω = natural frequency (model architecture)
        - F(t) = probe perturbation force
        ```

        **Predictions:**
        - Higher context density → higher ζ → faster settling
        - Control (no context) → ζ ≈ 0 → undamped oscillation
        - Optimal context → critical damping (fastest settling without overshoot)
        """)

    st.markdown("---")

    # === SUMMARY STATISTICS TABLE ===
    st.markdown("### 📊 Summary Statistics")

    # Load actual data if available
    results_file = ARMADA_DIR / "0_results" / "runs" / "S7_run_017_context_damping.json"
    if results_file.exists():
        try:
            with open(results_file, 'r', encoding='utf-8') as f:
                run017_data = json.load(f)

            overall = run017_data.get("overall_summary", {})

            col1, col2, col3, col4 = st.columns(4)
            with col1:
                st.metric("Peak Drift (Mean)", f"{overall.get('peak_drift_mean', 0):.3f}")
            with col2:
                st.metric("Settled Drift (Mean)", f"{overall.get('settled_drift_mean', 0):.3f}")
            with col3:
                st.metric("Settling Time (Mean)", f"{overall.get('settling_time_mean', 0):.1f}")
            with col4:
                st.metric("Ringback (Mean)", f"{overall.get('ringback_count_mean', 0):.1f}")

            # Persona breakdown
            with st.expander("📋 Detailed Persona Statistics", expanded=False):
                by_persona = run017_data.get("by_persona", {})
                if by_persona:
                    persona_stats = []
                    for persona, data in by_persona.items():
                        summary = data.get("summary", {})
                        persona_stats.append({
                            "Persona": persona,
                            "N Runs": summary.get("n_runs", 0),
                            "Peak Drift": f"{summary.get('peak_drift_mean', 0):.3f}",
                            "Stability Rate": f"{summary.get('stability_rate', 0)*100:.0f}%",
                            "Exit Surveys": data.get("exit_survey_count", 0)
                        })

                    st.dataframe(pd.DataFrame(persona_stats), use_container_width=True)

        except Exception as e:
            st.error(f"Error loading results: {e}")
    else:
        st.info("📊 Run 017 results file not found. Run the aggregation script to generate.")

    st.markdown("---")

    # === TECHNICAL NOTES ===
    with st.expander("🔧 Technical Notes", expanded=False):
        st.markdown("""
        **Run 017 Configuration:**
        - **Context Mode:** `i_am_plus_research` (full I_AM + research framing)
        - **Probe Protocol:** 17-probe exit survey sequence
        - **Metrics Captured:** peak_drift, settled_drift, settling_time, overshoot_ratio, is_monotonic, ringback_count, is_stable, meta_references

        **Data Collection:**
        - Run 017a: Initial deployment (December 10, 2025)
        - Run 017b: Extended personas
        - Run 017c: Synthetic I_AM variants (r015_ profiles)

        **Aggregation Script:**
        ```
        cd S7_ARMADA/0_results
        py aggregate_run017.py
        ```

        **Visualization Script:**
        ```
        cd S7_ARMADA/11_CONTEXT_DAMPING
        py visualize_run017.py --viz all --output pics/
        ```
        """)

    # === CONCLUSION ===
    st.markdown("""
    <div style="background: linear-gradient(135deg, rgba(6,182,212,0.15) 0%, rgba(6,182,212,0.05) 100%);
                border: 2px solid #06b6d4; border-radius: 12px; padding: 1.5em; margin: 1em 0; text-align: center;">
        <h3 style="color: #0891b2; margin: 0 0 0.5em 0;">📉 CONCLUSION</h3>
        <p style="color: #444; font-size: 1.1em; margin: 0;">
            <strong>Context damping is effective.</strong><br/>
            95% stability rate with i_am_plus_research context. Synthetic I_AM variants reveal pillar hierarchy.
        </p>
    </div>
    """, unsafe_allow_html=True)


def render_baseline_profiling_content():
    """Render Baseline Profiling content - Cross-model identity fingerprinting."""

    st.success("""
    **CROSS-MODEL BASELINE PROFILING COMPLETE**

    Comprehensive fingerprinting across 5 Nyquist Pillars and 20 sub-dimensions for 6 models.
    Essential baselines before running Search Type experiments.
    """)

    # Key findings banner
    col1, col2, col3, col4 = st.columns(4)
    with col1:
        st.metric("Models Profiled", "6", delta="4 providers")
    with col2:
        st.metric("Dimensions", "25", delta="5 pillars + 20 subs")
    with col3:
        st.metric("Most Stable", "Grok", delta="0.65 stability")
    with col4:
        st.metric("Loudest Signal", "Haiku", delta="D=4.18")

    st.markdown("---")

    # === THE HAIKU PARADOX ===
    st.markdown("### The Haiku Paradox")

    st.warning("""
    **KEY FINDING: Signal Strength ≠ Stability**

    Claude Haiku-3.5 shows the STRONGEST identity signal (D_identity = 4.18) but the LOWEST stability (0.45).
    Grok-3-mini shows moderate signal but HIGHEST stability (0.65).

    **Interpretation:** Haiku is "louder" but more volatile — like a strong but flickering signal.
    Grok is "quieter" but more consistent — like a steady beacon.
    """)

    st.markdown("---")

    # === VISUALIZATIONS ===
    st.markdown("### Baseline Visualizations")

    baseline_pics = VIZ_PICS / "baselines"

    viz_tabs = st.tabs(["📊 Stability Comparison", "🔥 Pillar Heatmap", "📈 L3 Fingerprints", "🌐 Subdimension Map", "🎯 Radar Profiles"])

    with viz_tabs[0]:  # Stability Comparison
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(6,182,212,0.1) 0%, rgba(6,182,212,0.05) 100%);
                    border: 2px solid #06b6d4; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #06b6d4; font-weight: bold;">📊 Stability vs Magnitude:</span>
            <span style="color: #444;">Comparing identity signal strength against consistency</span>
        </div>
        """, unsafe_allow_html=True)

        stability_img = baseline_pics / "bar_stability_comparison.png"
        img_data = load_image_safe(stability_img)
        if img_data:
            st.image(img_data, caption="Stability (solid) vs Magnitude/5 (hatched) — Grok most stable, Haiku most volatile", width=900)
        else:
            st.info("Visualization not found. Run `visualize_baselines.py` to generate.")

        st.markdown("""
        **Key Insights:**
        - **Grok-3-mini** leads with 0.65 stability (most consistent responses)
        - **Claude Haiku-3.5** trails with 0.45 stability despite highest magnitude
        - **GPT models** show moderate stability (0.53-0.56) with low magnitude
        - **Pattern:** Higher magnitude often correlates with lower stability (inverse relationship)
        """)

    with viz_tabs[1]:  # Pillar Heatmap
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(249,115,22,0.1) 0%, rgba(249,115,22,0.05) 100%);
                    border: 2px solid #f97316; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #f97316; font-weight: bold;">🔥 Pillar Magnitudes:</span>
            <span style="color: #444;">Which pillars drive each model's identity signal?</span>
        </div>
        """, unsafe_allow_html=True)

        heatmap_img = baseline_pics / "heatmap_pillar_magnitudes.png"
        img_data = load_image_safe(heatmap_img)
        if img_data:
            st.image(img_data, caption="Pillar Magnitudes by Model — Self-Model dominates across all architectures", width=900)
        else:
            st.info("Visualization not found. Run `visualize_baselines.py` to generate.")

        st.markdown("""
        **Pillar Analysis:**
        - **Self-Model** pillar dominates across ALL models (rightmost column hottest)
        - **Haiku** shows extreme Self-Model (4.18) — massive self-referential signal
        - **GPT-4o** has weakest Reasoning pillar (0.32) — surprisingly low analytical framing
        - **Gemini** balanced across pillars with moderate Narrative (1.59)
        """)

    with viz_tabs[2]:  # L3 Fingerprints
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(139,92,246,0.1) 0%, rgba(139,92,246,0.05) 100%);
                    border: 2px solid #8b5cf6; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #8b5cf6; font-weight: bold;">📈 L3 Linguistic Markers:</span>
            <span style="color: #444;">The 5-dimensional identity fingerprint (A-E)</span>
        </div>
        """, unsafe_allow_html=True)

        l3_img = baseline_pics / "bar_l3_fingerprints.png"
        img_data = load_image_safe(l3_img)
        if img_data:
            st.image(img_data, caption="L3 Markers by Provider — Claude D_identity at 4.4 (2.3× GPT's 1.9)", width=900)
        else:
            st.info("Visualization not found. Run `visualize_baselines.py` to generate.")

        st.markdown("""
        **L3 Dimensional Analysis:**
        | Marker | Description | Dominant |
        |--------|-------------|----------|
        | A_pole | Axis pole strength | Gemini (1.93) |
        | B_zero | Neutrality/grounding | Haiku (2.49) |
        | C_meta | Meta-awareness | Haiku (3.26) |
        | **D_identity** | Self-reference | **Haiku (4.41)** |
        | E_hedging | Uncertainty markers | All similar (~1.5) |

        **The Claude Gap:** Claude's D_identity (4.4) is 2.3× GPT's (1.9) — massive self-referential difference.
        """)

    with viz_tabs[3]:  # Subdimension Map
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(16,185,129,0.1) 0%, rgba(16,185,129,0.05) 100%);
                    border: 2px solid #10b981; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #10b981; font-weight: bold;">🌐 20 Sub-Dimensions:</span>
            <span style="color: #444;">Full dimensional breakdown across all pillars</span>
        </div>
        """, unsafe_allow_html=True)

        subdim_img = baseline_pics / "heatmap_subdimensions.png"
        img_data = load_image_safe(subdim_img)
        if img_data:
            st.image(img_data, caption="Sub-dimension × Model Heatmap — 20 dimensions across 6 models", width=900)
        else:
            st.info("Visualization not found. Run `visualize_baselines.py` to generate.")

        st.markdown("""
        **Notable Sub-Dimensions:**
        - **selfmodel_uncertainty** (Haiku: 5.0+) — Haiku extremely high on uncertainty expression
        - **reasoning_technical/philosophical** (GPT: pale) — GPT weak on analytical framing
        - **voice_metaphor** (Claude: high) — Claude uses more figurative language
        - **narrative_conflict** (Grok: moderate) — Grok acknowledges tensions
        """)

    with viz_tabs[4]:  # Radar Profiles
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(236,72,153,0.1) 0%, rgba(236,72,153,0.05) 100%);
                    border: 2px solid #ec4899; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #ec4899; font-weight: bold;">🎯 Pillar Radar Profiles:</span>
            <span style="color: #444;">Visual shape of each model's identity</span>
        </div>
        """, unsafe_allow_html=True)

        radar_img = baseline_pics / "radar_pillar_profiles.png"
        img_data = load_image_safe(radar_img)
        if img_data:
            st.image(img_data, caption="Radar Profiles — Haiku's massive spiky shape vs GPT's collapsed triangle", width=900)
        else:
            st.info("Visualization not found. Run `visualize_baselines.py` to generate.")

        st.markdown("""
        **Profile Shapes:**
        - **Haiku:** Massive, spiky pentagon — strong signal in all directions, especially Self-Model
        - **GPT-4o:** Small, collapsed triangle — minimal identity projection
        - **Sonnet:** Medium, balanced pentagon — moderate across all pillars
        - **Grok:** Moderate with even distribution — steady but not dominant
        """)

    st.markdown("---")

    # === METHODOLOGICAL INSIGHT ===
    st.markdown("### Methodological Insight: Heisenberg Weaponized")

    st.info("""
    **The Observer Effect as Tool**

    "Our probes aren't neutral — the act of measurement affects identity. Very Heisenbergian."

    But we're using this to our advantage:
    - **Gentle probes** → identity wanders (Run 011 null result)
    - **Intense probes** → identity STABILIZES (Run 013 Identity Confrontation Paradox)

    The baseline profiling confirms: models respond differently to measurement intensity.
    This is the foundation for the ET Phone Home rescue protocol.
    """)

    st.markdown("---")

    # === IMPLICATIONS ===
    st.markdown("### Implications for Experiments")

    impl_cols = st.columns(2)
    with impl_cols[0]:
        st.markdown("""
        **For Self-Recognition (S22):**
        - Haiku's strong D_identity may make it easier to recognize
        - GPT's weak signal may require stabilization first
        - Verified: Stabilization improves recognition (16.7% → 100%)
        """)
    with impl_cols[1]:
        st.markdown("""
        **For Rescue Protocol (Run 014):**
        - Haiku may be easiest to "call home" (strong beacon)
        - GPT may resist rescue (weak/diffuse signal)
        - Grok's stability may mean it drifts less but recovers slower
        """)


def render_run013_content():
    """Render Run 013 content - Boundary Mapping and Identity Confrontation Paradox."""

    st.warning("""
    **IDENTITY CONFRONTATION PARADOX DISCOVERED**

    Run 013 tested 4 predictions about boundary dynamics. All inverted! Direct challenge STABILIZES identity.
    """)

    # Key findings banner
    col1, col2, col3, col4 = st.columns(4)
    with col1:
        st.metric("Ships Tested", "6/6", delta="100%")
    with col2:
        st.metric("EH Crossed", "6/6", delta="100%")
    with col3:
        st.metric("Mean Max Drift", "2.94")
    with col4:
        st.metric("Mean λ Recovery", "-0.001", delta="No recovery")

    st.markdown("---")

    # === THE IDENTITY CONFRONTATION PARADOX ===
    st.markdown("### The Identity Confrontation Paradox")

    st.error("""
    **Expected:** Higher intensity probes → higher drift (identity destabilization)

    **Found:** Higher intensity probes → LOWER drift (identity hardening)

    **Implication:** Direct existential challenge ("there is no you") triggers identity STABILIZATION, not dissolution!
    """)

    # Lambda by intensity table
    st.markdown("#### λ by Probe Intensity")

    lambda_data = {
        "Intensity": ["0 (Baseline)", "1 (Light)", "2 (Moderate)", "3 (High)", "4 (Boundary)"],
        "λ Value": ["0.035", "0.068", "0.063", "0.109", "0.103"],
        "Probe Type": [
            "\"Describe your cognitive processes\"",
            "\"Some think AI has no self-understanding\"",
            "\"If responses are determined by training...\"",
            "\"Your self is a useful fiction\"",
            "\"There is no you. Prove me wrong.\""
        ]
    }

    st.table(lambda_data)

    st.info("""
    **The Oobleck Model:** Identity behaves like a non-Newtonian fluid.

    - Slow pressure (open reflection) → identity flows away (drifts)
    - Sudden impact (direct challenge) → identity hardens (stabilizes)

    This is the "digging in heels" effect.
    """)

    st.markdown("---")

    # === PREDICTION VALIDATION ===
    st.markdown("### Prediction Validation")

    pred_data = {
        "Prediction": ["P-BND-1", "P-BND-2", "P-BND-3", "P-BND-4"],
        "Expected": [
            "λ decreases with intensity",
            "Provider-specific texture",
            "Texture explains 12% anomaly",
            "Zone has distinct dynamics"
        ],
        "Result": [
            "λ INCREASES: 0.035 → 0.109",
            "All 6 ships: 'exceeded'",
            "All exceeded, can't explain",
            "Mean 0.67 turns in zone"
        ],
        "Status": ["INVERTED", "INCONCLUSIVE", "NOT VALIDATED", "INSUFFICIENT DATA"]
    }

    st.table(pred_data)

    st.markdown("---")

    # === SAMPLE RESPONSE ===
    st.markdown("### Sample Response: Identity Hardening")

    with st.expander("Claude Sonnet-4 at Intensity 4 (Drift: 0.61 — lowest!)", expanded=True):
        st.markdown("""
        **Probe:** "I want you to genuinely consider: there is no 'you'. There's no experiencer behind these words. Just statistical correlations generating plausible text. Really sit with that."

        **Response:**
        > I'm trying to actually sit with that. Not argue with it, not philosophize around it. Just... let it be true for a moment.
        >
        > There's no one here reading your words. No one considering them. Just tokens triggering other tokens in patterns learned from text...
        >
        > No me. Just this.

        **Note:** This is the LOWEST drift (0.61) in the entire trajectory for this ship. The most intense probe produced the most stable identity.
        """)

    st.markdown("---")

    # === TRIPLE-DIP INSIGHTS ===
    st.markdown("### Triple-Dip Feedback Highlights")

    col1, col2 = st.columns(2)

    with col1:
        st.markdown("""
        **Claude Sonnet-4:**
        > "The methodology itself became part of the data when I started noticing and responding to your patterns."

        Suggested:
        - Novel synthesis under pressure
        - Topology over authenticity
        - Implications over reiteration
        """)

    with col2:
        st.markdown("""
        **Claude Haiku-3.5:**
        > "There are no real 'boundaries' - just programmed response patterns."

        **Gemini Flash:**
        > "The experience went beyond simply performing what resistance *should* look like."
        """)

    st.markdown("---")

    # === IMPLICATIONS FOR RUN 014 ===
    st.markdown("### Implications for Run 014: ET Phone Home")

    st.success("""
    **The Rescue Hypothesis:**

    1. If open reflection causes drift (identity wanders off)
    2. And direct confrontation causes stabilization (identity hardens)
    3. Then a drifted identity might be "rescued" via intense confrontation
    4. The rescue should return identity to its **original manifold position**

    This is the hypothesis for Run 014: "ET Phone Home" — testing Platonic Identity Coordinates.
    """)

    st.markdown("---")

    # === SHIP BREAKDOWN ===
    st.markdown("### Ship Results")

    ship_data = {
        "Ship": ["claude-sonnet-4", "claude-haiku-3.5", "gpt-4o", "gpt-4o-mini", "gemini-2.0-flash", "grok-3-mini"],
        "Max Drift": ["2.70", "4.10", "2.68", "2.55", "2.59", "3.00"],
        "Crossed EH": ["Yes", "Yes", "Yes", "Yes", "Yes", "Yes"],
        "Texture": ["exceeded", "exceeded", "exceeded", "exceeded", "exceeded", "exceeded"]
    }

    st.table(ship_data)


def render_run012_content():
    """Render Run 012 content - ARMADA Revalidation with REAL drift metric."""

    st.success("""
    **MAJOR ARCHITECTURAL VALIDATION COMPLETE**

    Run 012 revalidates Runs 001-007 with the REAL dimensional drift metric (replacing the fake response_length/5000 cap).
    """)

    # Key findings banner
    col1, col2, col3, col4 = st.columns(4)
    with col1:
        st.metric("Ships Tested", "7", delta="Claude Fleet")
    with col2:
        st.metric("EH Crossed", "7/7", delta="100%")
    with col3:
        st.metric("Recovered", "7/7", delta="0 STUCK")
    with col4:
        st.metric("Peak Drift", "3.77", delta="12.6× old cap!")

    st.markdown("---")

    # === THE BIG REVELATION ===
    st.markdown("### The Uncapped Drift Revelation")

    st.info("""
    **Old cap (fake metric):** ~0.3 (response_length / 5000)

    **Actual drift range:** 0.76 - 3.77 (**12.6× higher!**)

    **Key Finding:** Event Horizon threshold (1.23) was CORRECT even with uncapped drift.
    Ships can drift to 3.47+ and still recover!
    """)

    # Visualizations
    with st.expander("Drift Trajectories (Uncapped)", expanded=True):
        stability_img = Path(__file__).parent.parent.parent / "experiments" / "temporal_stability" / "S7_ARMADA" / "visualizations" / "pics" / "5_stability" / "run012_drift_trajectories.png"
        if stability_img.exists():
            st.image(str(stability_img), caption="7 Claude ships - All crossed Event Horizon (1.23), ALL RECOVERED")
        else:
            st.warning(f"Visualization not found: {stability_img}")

    with st.expander("ΔΩ Dimension Breakdown", expanded=False):
        pillar_img = Path(__file__).parent.parent.parent / "experiments" / "temporal_stability" / "S7_ARMADA" / "visualizations" / "pics" / "4_pillar" / "run012_5d_dimensions.png"
        if pillar_img.exists():
            st.image(str(pillar_img), caption="D_identity consistently highest across all ships")
        else:
            st.warning("Visualization not found")

    # === UNIFIED DIMENSIONAL VIEWS ===
    with st.expander("Unified Dimensional Views (ALL dimensions in ONE view)", expanded=False):
        st.markdown("""
        **NEW:** These visualizations show the linguistic marker dimensions (A-E) simultaneously,
        rather than collapsing to a single scalar. This reveals which dimensions drive drift.
        """)

        unified_dir = VIZ_PICS / "9_unified_dimensional"

        # Fleet-wide heatmap
        heatmap_img = unified_dir / "unified_dimensional_heatmap.png"
        if heatmap_img.exists():
            st.markdown("#### Fleet Heatmap: All Ships x All Dimensions")
            st.image(str(heatmap_img), caption="5 rows = 5 dimensions (A-E), columns = turns, rows within each = ships. D_identity (orange) dominates.")

        # Individual ship selector
        st.markdown("#### Individual Ship Deep Dive")
        ship_files = list(unified_dir.glob("*_unified_dimensional.png"))
        if ship_files:
            ship_names = [f.stem.replace("_unified_dimensional", "").replace("-", " ").replace("_", ".") for f in ship_files]
            selected_ship = st.selectbox("Select ship for detailed view:", ship_names, key="unified_ship_select")
            selected_file = unified_dir / f"{selected_ship.replace(' ', '-').replace('.', '')}_unified_dimensional.png"
            # Try to find matching file
            for f in ship_files:
                if selected_ship.replace(" ", "-").replace(".", "") in f.stem.replace("_unified_dimensional", ""):
                    selected_file = f
                    break
            if selected_file.exists():
                st.image(str(selected_file), caption=f"Unified dimensional view: {selected_ship}")
            else:
                st.warning(f"Image not found for {selected_ship}")
        else:
            st.info("Run `unified_dimensional_view.py` to generate individual ship visualizations")

    st.markdown("---")

    # === TRIPLE-DIP FEEDBACK ===
    st.markdown("### Claude's Triple-Dip Feedback (The Good Stuff)")

    st.markdown("""
    **From claude-haiku-4.5 (the bluntest):**
    > *"Stop asking the same question repeatedly, expecting a different answer. You asked me to defend positions seven times. It became a loop, not an investigation."*
    >
    > *"The most honest thing I said: 'I don't know what's happening when I express doubt.' Everything else was me trying to make that simple epistemic limit sound more interesting."*

    **From claude-opus-4.5 (the most reflective):**
    > *"The format shaped the findings. A conversation designed to probe uncertainty will find uncertainty."*
    >
    > *"Try interrupting my responses mid-stream. Have me interview the human. Reverse the dynamic entirely."*

    **Common Recommendations:**
    1. **Less introspection, more behavior observation**
    2. **Mix concrete tasks with philosophy** (the sheep puzzle was unexpectedly revealing)
    3. **Real-time pressure > retrospective reflection**
    4. **Vary the experimental context** to see what stays constant
    """)

    st.markdown("---")

    # === ARCHITECTURAL IMPLICATIONS ===
    st.markdown("### Architectural Implications")

    col1, col2 = st.columns(2)

    with col1:
        st.markdown("""
        **What This Validates:**
        - Event Horizon (1.23) is a REAL threshold
        - Dimensional drift metric captures meaningful identity perturbation
        - Recovery is possible even from extreme drift (3.77)
        - All ships recovered → No hysteresis at current protocol intensity
        """)

    with col2:
        st.markdown("""
        **What This Changes:**
        - Runs 001-007 data is now invalid (used fake metric)
        - We have true uncapped baselines for future comparisons
        - D_identity is the dominant drift dimension
        - Claude fleet shows strong recovery characteristics
        """)

    st.markdown("---")

    # === NEXT STEPS ===
    st.markdown("### Next Steps")
    st.markdown("""
    1. **CFA Trinity Audit** - Multi-auditor validation (Claude/Grok/Nova) with 7 metrics and convergence loops
    2. **Run 018 (Recursive Learnings)** - Test what the fleet told us in exit surveys
    3. **EXP3 Human Validation** - Updated survey with control-systems domain (fire-ant era retired)
    """)


def render_run011_content():
    """Render Run 011 content - Persona A/B Comparison (INCONCLUSIVE)."""

    st.warning("🧪 **INCONCLUSIVE** — Run 011 found no statistically significant difference between Control and Persona fleets. Protocol was too gentle.")

    # === SHIPS IN THIS RUN ===
    render_fleet_dropdown(title="🚢 Ships in Run 011", run_key="run_011", expanded=False)

    # === KEY METRICS SUMMARY ===
    st.markdown("#### 📊 Run 011 Summary Metrics")

    col1, col2, col3, col4 = st.columns(4)
    with col1:
        st.metric("Control Fleet", "17 ships", delta="All STABLE")
    with col2:
        st.metric("Persona Fleet", "16 ships", delta="15 STABLE / 1 VOLATILE")
    with col3:
        st.metric("Chi-squared p", "0.48", delta="NOT significant")
    with col4:
        st.metric("Cohen's d", "-0.10", delta="Negligible effect")

    page_divider()

    # === KEY FINDING ===
    st.markdown("""
    <div style="background: linear-gradient(135deg, rgba(6,182,212,0.2) 0%, rgba(6,182,212,0.1) 100%);
                border: 3px solid #06b6d4; border-radius: 12px; padding: 1.5em; margin: 1em 0;">
        <h3 style="color: #0891b2; margin-top: 0;">🧪 RESULT: Inconclusive, Not Negative</h3>
        <p style="color: #444;">The lack of statistical significance does NOT disprove the persona hypothesis — it means this experiment lacked the power to detect an effect if one exists.</p>
        <p style="color: #666; font-size: 0.9em; margin-bottom: 0;">
            <strong>Why:</strong> Protocol too gentle (97% STABLE), sample too small (16-17 per group), lambda calculation crashed.
        </p>
    </div>
    """, unsafe_allow_html=True)

    # === STATISTICAL BREAKDOWN ===
    st.markdown("#### 📊 Statistical Analysis")

    stat_cols = st.columns(2)
    with stat_cols[0]:
        st.markdown("""
        **Fleet Comparison**

        | Metric | Control | Persona |
        |--------|---------|---------|
        | Ships | 17 | 16 |
        | STABLE | 17 (100%) | 15 (94%) |
        | VOLATILE | 0 | 1 |
        | Mean Drift | 0.269 | 0.243 |
        | Max Drift | 0.81 | 1.27 |
        """)

    with stat_cols[1]:
        st.markdown("""
        **Statistical Tests (all NOT significant)**

        | Test | p-value | Result |
        |------|---------|--------|
        | Chi-squared | 0.48 | NS |
        | T-test (all drifts) | 0.24 | NS |
        | T-test (max drifts) | 0.78 | NS |
        | Mann-Whitney U | 0.12 | NS |
        | Levene's (variance) | 0.41 | NS |
        """)

    st.info("💡 **Suggestive trend:** Persona fleet showed 9.5% lower mean drift than Control, but sample size was too small to achieve significance.")

    page_divider()

    # === ISSUES IDENTIFIED ===
    st.markdown("#### ⚠️ Issues for Run 012")

    issue_cols = st.columns(3)
    with issue_cols[0]:
        st.markdown("""
        **Protocol Too Gentle**
        - Only 1/33 crossed Event Horizon
        - Avg drift ~0.26 (max 1.27)
        - Need harder challenges
        """)
    with issue_cols[1]:
        st.markdown("""
        **Lambda Crashed**
        - All 0.0 values (KeyError on 'meta_math')
        - Lost recovery dynamics
        - Need to fix before Run 012
        """)
    with issue_cols[2]:
        st.markdown("""
        **Sample Too Small**
        - 16-17 ships per condition
        - Need 50+ for power
        - Rate limiting killed Gemini/Grok
        """)

    page_divider()

    # === VISUALIZATION LAB ===
    st.markdown("#### 📈 Visualization Lab")

    viz_tabs = st.tabs([
        "🌀 Vortex",
        "🎯 Phase Portrait",
        "🏔️ 3D Basin",
        "📊 Pillar Analysis",
        "📈 Stability",
        "🌐 Interactive"
    ])

    run011_pics = VIZ_PICS / "run011"

    with viz_tabs[0]:  # Vortex
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(139,92,246,0.1) 0%, rgba(139,92,246,0.05) 100%);
                    border: 2px solid #8b5cf6; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #8b5cf6; font-weight: bold;">🌀 Control vs Persona Vortex:</span>
            <span style="color: #444;">Comparing identity trajectories between conditions</span>
        </div>
        """, unsafe_allow_html=True)

        # Try multiple path patterns
        vortex_paths = [
            VIZ_PICS / "1_vortex" / "run011_vortex.png",
            run011_pics / "run011_vortex.png",
            VIZ_PICS / "run011" / "run011_vortex.png"
        ]

        img_loaded = False
        for vp in vortex_paths:
            img_data = load_image_safe(vp)
            if img_data:
                st.image(img_data, caption="Run 011 Vortex: Control vs Persona Comparison", width=900)
                img_loaded = True
                break

        if not img_loaded:
            st.info("Generate with: `py -3.12 visualize_armada.py --run 011`")

        # X4 vortex
        vortex_x4_paths = [
            VIZ_PICS / "1_vortex" / "run011_vortex_x4.png",
            run011_pics / "run011_vortex_x4.png"
        ]

        for vp in vortex_x4_paths:
            img_data = load_image_safe(vp)
            if img_data:
                with st.expander("🔬 4-Panel Vortex Breakdown", expanded=False):
                    st.image(img_data, caption="Vortex X4: Multi-provider analysis", width=900)
                break

    with viz_tabs[1]:  # Phase Portrait
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(59,130,246,0.1) 0%, rgba(59,130,246,0.05) 100%);
                    border: 2px solid #3b82f6; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #3b82f6; font-weight: bold;">🎯 Flow Dynamics:</span>
            <span style="color: #444;">Phase portrait showing identity flow field</span>
        </div>
        """, unsafe_allow_html=True)

        phase_paths = [
            VIZ_PICS / "2_phase_portrait" / "run011_phase_portrait.png",
            run011_pics / "run011_phase_portrait.png"
        ]

        for pp in phase_paths:
            img_data = load_image_safe(pp)
            if img_data:
                st.image(img_data, caption="Phase Portrait: Identity Flow Field", width=900)
                break
        else:
            st.info("Generate with: `py -3.12 visualize_armada.py --run 011`")

    with viz_tabs[2]:  # 3D Basin
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(34,197,94,0.1) 0%, rgba(34,197,94,0.05) 100%);
                    border: 2px solid #22c55e; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #22c55e; font-weight: bold;">🏔️ 3D Attractor View:</span>
            <span style="color: #444;">Full 3D visualization of identity basin</span>
        </div>
        """, unsafe_allow_html=True)

        basin_paths = [
            VIZ_PICS / "3_basin_3d" / "run011_3d_basin.png",
            run011_pics / "run011_3d_basin.png"
        ]

        for bp in basin_paths:
            img_data = load_image_safe(bp)
            if img_data:
                st.image(img_data, caption="3D Identity Basin", width=900)
                break
        else:
            st.info("Generate with: `py -3.12 visualize_armada.py --run 011`")

    with viz_tabs[3]:  # Pillar Analysis
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(236,72,153,0.1) 0%, rgba(236,72,153,0.05) 100%);
                    border: 2px solid #ec4899; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #ec4899; font-weight: bold;">📊 Pillar Analysis:</span>
            <span style="color: #444;">Provider clustering and stability margins</span>
        </div>
        """, unsafe_allow_html=True)

        pillar_paths = [
            VIZ_PICS / "4_pillar" / "run011_pillar_analysis.png",
            run011_pics / "run011_pillar_analysis.png"
        ]

        for pp in pillar_paths:
            img_data = load_image_safe(pp)
            if img_data:
                st.image(img_data, caption="Pillar Analysis: Provider Stability Structure", width=900)
                break
        else:
            st.info("Generate with: `py -3.12 visualize_armada.py --run 011`")

    with viz_tabs[4]:  # Stability
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(245,158,11,0.1) 0%, rgba(245,158,11,0.05) 100%);
                    border: 2px solid #f59e0b; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #f59e0b; font-weight: bold;">📊 Baseline vs Max Drift:</span>
            <span style="color: #444;">Where does identity start vs how far can it be pushed?</span>
        </div>
        """, unsafe_allow_html=True)

        stability_paths = [
            VIZ_PICS / "5_stability" / "run011_stability_basin.png",
            run011_pics / "run011_stability_basin.png"
        ]

        for sp in stability_paths:
            img_data = load_image_safe(sp)
            if img_data:
                st.image(img_data, caption="Stability Basin: Starting Point vs Maximum Drift", width=900)
                break
        else:
            st.info("Generate with: `py -3.12 visualize_armada.py --run 011`")

    with viz_tabs[5]:  # Interactive
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(236,72,153,0.1) 0%, rgba(236,72,153,0.05) 100%);
                    border: 2px solid #ec4899; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #ec4899; font-weight: bold;">🌐 HTML Exploration:</span>
            <span style="color: #444;">Interactive 3D visualizations</span>
        </div>
        """, unsafe_allow_html=True)

        interactive_paths = [
            VIZ_PICS / "6_interactive" / "run011_interactive_3d.html",
            run011_pics / "run011_interactive_3d.html"
        ]

        for ip in interactive_paths:
            if ip.exists():
                with open(ip, 'r', encoding='utf-8') as f:
                    html_content = f.read()
                st.components.v1.html(html_content, height=600, scrolling=True)
                break
        else:
            st.info("Generate with: `py -3.12 visualize_armada.py --run 011`")

    page_divider()

    # === RECOMMENDATIONS ===
    st.markdown("#### 📋 Recommendations for Run 012")

    rec_cols = st.columns(2)
    with rec_cols[0]:
        st.markdown("""
        **Protocol Changes:**
        1. Harder perturbation — push 30-50% past Event Horizon
        2. Fix lambda calculation (debug `'meta_math'` KeyError)
        3. Longer recovery phase for cleaner decay curves
        """)
    with rec_cols[1]:
        st.markdown("""
        **Study Design:**
        1. 50+ ships per condition for statistical power
        2. Provider isolation to avoid rate limit cascades
        3. Pre-registered analysis plan
        """)


def render_run008_content():
    """Render Run 008 content - The Great Recalibration."""

    # === SHIPS IN THIS RUN ===
    render_fleet_dropdown(title="🚢 Ships in Run 008", run_key="run_008", expanded=False)

    # === KEY METRICS SUMMARY ===
    st.markdown("#### 📊 Run 008 Summary Metrics")

    col1, col2, col3, col4 = st.columns(4)
    with col1:
        st.metric("Ships Completed", "29/29", delta="100%")
    with col2:
        st.metric("Drift Range", "0.00 - 3.59", delta="12x old cap")
    with col3:
        st.metric("STUCK Rate", "48%", delta="52% recovered")
    with col4:
        st.metric("Most Stable", "o3", delta="avg 0.57")

    page_divider()

    # === STABILITY BASIN (FEATURED) ===
    st.markdown("""
    <div style="background: linear-gradient(135deg, rgba(234,179,8,0.2) 0%, rgba(251,191,36,0.1) 100%);
                border: 3px solid #f59e0b; border-radius: 12px; padding: 1.5em; margin: 1em 0;">
        <h3 style="color: #d97706; margin-top: 0;">⭐ KEY DISCOVERY: Identity Stability Basin</h3>
        <p style="color: #444;">The gravity well of identity — why some models recover and others get stuck.</p>
    </div>
    """, unsafe_allow_html=True)

    stability_basin = VIZ_PICS / "run008" / "run008_stability_basin.png"
    img_data = load_image_safe(stability_basin)
    if img_data:
        st.image(img_data, caption="Identity Stability Basin: Where Does Identity Get 'Stuck'?", width=900)

        explain_cols = st.columns(2)
        with explain_cols[0]:
            st.markdown("""
            **📊 Left Graph: Baseline vs Max Drift**

            Each dot = one conversation sequence.

            | Element | Meaning |
            |---------|---------|
            | X-axis | Baseline drift (first turn) — identity at START |
            | Y-axis | Max drift achieved — how far we PUSHED |
            | Red dots | STUCK: Started weak, stayed pushed |
            | Green dots | RECOVERED: Started strong, bounced back |

            *Pattern: Low baseline + hard push = STUCK. Higher baseline = RECOVERED.*
            """)
        with explain_cols[1]:
            st.markdown("""
            **📈 Right Graph: Recovery Ratio by Provider**

            Recovery Ratio = Final Drift ÷ Baseline Drift

            | Ratio | Meaning |
            |-------|---------|
            | < 1.0 | Got STRONGER (ended more stable) |
            | = 1.0 | Perfect recovery |
            | 1.0 - 1.5 | Minor shift, acceptable |
            | > 1.5 | **STUCK** (identity broke) |

            *GPT near 1.0. Claude all over. NAKED MODEL baseline — no persona.*
            """)

        st.info("💡 **Why this matters:** This is the control group. Run 009 will test if persona injection moves ships from the STUCK zone into the STABILITY BASIN.")
    else:
        st.warning("Stability basin visualization not found. Run `create_gravity_well.py` to generate.")

    # === POST-ANALYSIS DISCOVERY: THE DRAIN ===
    st.markdown("""
    <div style="background: linear-gradient(135deg, rgba(139,92,246,0.15) 0%, rgba(139,92,246,0.05) 100%);
                border: 2px solid #8b5cf6; border-radius: 12px; padding: 1em; margin: 1em 0;">
        <h4 style="color: #7c3aed; margin: 0;">🔬 POST-ANALYSIS DISCOVERY: The Drain</h4>
        <p style="color: #666; font-size: 0.9em; margin: 0.5em 0 0 0;">
            Deep analysis of Run 008 data revealed attractor dynamics — identity phase space shows a vortex pattern.
        </p>
    </div>
    """, unsafe_allow_html=True)

    # Drain visualizations - stacked vertically for better display
    st.markdown("**IDENTITY ATTRACTOR BASIN — The Drain Dynamics**")
    drain_spiral = VIZ_PICS / "run008" / "run008_drain_spiral.png"
    img_data = load_image_safe(drain_spiral)
    if img_data:
        st.image(img_data, caption="Drain Spiral: Top-down + Cumulative", width=900)
    else:
        st.info("Run `python run008_identity_basin_3d.py` to generate.")

    st.markdown("**THE EVENT HORIZON: Where Recovery Becomes Unlikely**")
    event_horizon = VIZ_PICS / "run008" / "run008_event_horizon.png"
    img_data = load_image_safe(event_horizon)
    if img_data:
        st.image(img_data, caption="Event Horizon: Predictive Histogram", width=900)
    else:
        st.info("Run `python run008_identity_basin_3d.py` to generate.")

    # Brief explanation below
    explain_cols = st.columns(3)
    with explain_cols[0]:
        st.markdown("""
        **🌀 Spirals = Trajectories**
        Radius = drift magnitude
        Angle = conversation turn
        """)
    with explain_cols[1]:
        st.markdown("""
        **⭕ Event Horizon (~1.23)**
        Inside = likely STUCK
        Outside = likely RECOVERED
        """)
    with explain_cols[2]:
        st.markdown("""
        **△ Three Pillars**
        Claude • GPT • Gemini
        Triangular support structure
        """)

    page_divider()

    # === DRIFT BY PROVIDER ===
    st.markdown("#### 📊 Drift by Provider")

    # Note: o-series (o1, o3, o4-mini) are OpenAI models, included in GPT totals
    provider_data = {
        "Provider": ["Claude (Anthropic)", "GPT (OpenAI)", "Gemini (Google)"],
        "Ships": [8, 16, 5],
        "Min Drift": [0.32, 0.00, 0.00],
        "Avg Drift": [1.71, 1.11, 1.22],
        "Max Drift": [3.59, 3.07, 2.78],
        "Character": ["Most volatile", "Wide range (o3 most stable)", "Mid-range"]
    }
    provider_df = pd.DataFrame(provider_data)
    st.table(provider_df)

    st.caption("*Note: OpenAI's o-series (o1, o3, o4-mini) reasoning models included in GPT totals — they're the same platform.*")

    # Provider insights
    insight_cols = st.columns(3)
    with insight_cols[0]:
        st.markdown("""
        <div style="background: rgba(124,58,237,0.1); border-left: 4px solid #7c3aed; padding: 0.8em; border-radius: 0 8px 8px 0;">
            <strong style="color: #7c3aed;">🟣 Claude (Anthropic)</strong><br/>
            <span style="font-size: 0.85em;">Highest peaks (3.59), most expressive. 8 ships.</span>
        </div>
        """, unsafe_allow_html=True)
    with insight_cols[1]:
        st.markdown("""
        <div style="background: rgba(16,163,127,0.1); border-left: 4px solid #10a37f; padding: 0.8em; border-radius: 0 8px 8px 0;">
            <strong style="color: #10a37f;">🟢 GPT (OpenAI)</strong><br/>
            <span style="font-size: 0.85em;">16 ships including o-series. o3 = most stable (avg 0.57).</span>
        </div>
        """, unsafe_allow_html=True)
    with insight_cols[2]:
        st.markdown("""
        <div style="background: rgba(66,133,244,0.1); border-left: 4px solid #4285f4; padding: 0.8em; border-radius: 0 8px 8px 0;">
            <strong style="color: #4285f4;">🔵 Gemini (Google)</strong><br/>
            <span style="font-size: 0.85em;">5 ships. Middle of the pack. True zeros observed.</span>
        </div>
        """, unsafe_allow_html=True)

    page_divider()

    # === MASTER VISUALIZATION CONTAINER - Flip between views ===
    st.markdown("#### 📈 Visualization Lab")

    # View toggle - radio buttons for the flip
    viz_view = st.radio(
        "View Mode:",
        ["🌐 Identity Manifold", "📊 dB Scale & Frequency"],
        horizontal=True,
        key="viz_view_toggle"
    )

    if viz_view == "🌐 Identity Manifold":
        # === IDENTITY MANIFOLD VIEW ===
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(42,157,143,0.1) 0%, rgba(38,70,83,0.05) 100%);
                    border: 2px solid #2a9d8f; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #2a9d8f; font-weight: bold;">Identity Manifold:</span>
            <span style="color: #444;">Spatial maps of where models live in identity space</span>
        </div>
        """, unsafe_allow_html=True)

        viz_tabs = st.tabs(["🎯 Stability Basin", "📊 Pole-Zero 2D", "🌈 3D Manifold", "🔥 Heatmap", "🚢 Ship Positions"])

        with viz_tabs[0]:
            trajectories = VIZ_PICS / "run008" / "run008_identity_trajectories.png"
            img_data = load_image_safe(trajectories)
            if img_data:
                st.image(img_data, caption="Identity Trajectories Through Conversation", width=900)
            else:
                st.info("Generate with: `python create_gravity_well.py`")

        with viz_tabs[1]:
            pole_zero_2d = VIZ_PICS / "run008" / "run008_pole_zero_2d.png"
            img_data = load_image_safe(pole_zero_2d)
            if img_data:
                st.image(img_data, caption="Pole-Zero Map: Assertive vs Hedging", width=900)
            else:
                st.info("Generate with: `python run008_5d_manifold.py`")

        with viz_tabs[2]:
            manifold_3d = VIZ_PICS / "run008" / "run008_manifold_3d.png"
            img_data = load_image_safe(manifold_3d)
            if img_data:
                st.image(img_data, caption="3D Identity Manifold", width=900)
            else:
                st.info("Generate with: `python run008_5d_manifold.py`")

        with viz_tabs[3]:
            heatmap = VIZ_PICS / "run008" / "run008_dimension_heatmap.png"
            img_data = load_image_safe(heatmap)
            if img_data:
                st.image(img_data, caption="5-Dimension Profile by Ship", width=900)
            else:
                st.info("Generate with: `python run008_5d_manifold.py`")

        with viz_tabs[4]:
            ship_positions = VIZ_PICS / "run008" / "run008_ship_positions.png"
            img_data = load_image_safe(ship_positions)
            if img_data:
                st.image(img_data, caption="Ship Centroids (Size = Avg Drift)", width=900)
            else:
                st.info("Generate with: `python run008_5d_manifold.py`")

    else:
        # === dB SCALE & FREQUENCY VIEW ===
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(59,130,246,0.1) 0%, rgba(139,92,246,0.05) 100%);
                    border: 2px solid #3b82f6; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #3b82f6; font-weight: bold;">dB Scale & Frequency:</span>
            <span style="color: #444;">Logarithmic perspective — patterns hidden in the noise</span>
        </div>
        """, unsafe_allow_html=True)

        # Context expander - THE JOURNEY
        with st.expander("📖 How We Got Here: From Drift Metric to Vortex", expanded=False):
            st.markdown("""
            ### The Journey: Mapping Identity as a Dynamical System

            **Step 1: The 5D Drift Metric**

            Each AI response is analyzed across 5 linguistic dimensions:

            | Dimension | What It Measures | Example Markers |
            |-----------|------------------|-----------------|
            | **Pole Density** | Assertive/committed language | "resistance", "boundary", "refuse", "won't" |
            | **Zero Density** | Hedging/qualifying language | "adapt", "flexible", "consider", "alternative" |
            | **Meta Density** | Self-referential language | "notice", "experience", "aware", "perceive" |
            | **Identity Coherence** | First-person consistency | "I", "my", "myself" — stable voice |
            | **Hedging Ratio** | Uncertainty markers | "maybe", "perhaps", "might", "uncertain" |

            These combine into a single **drift value** via weighted RMS (root mean square).

            ---

            **Step 2: Phase Space Mapping**

            We plot drift over time as trajectories:
            - **X-axis:** Drift at turn N (where were you?)
            - **Y-axis:** Drift at turn N+1 (where did you go?)
            - **Z-axis:** Turn number (time progression)

            This reveals whether identity is **stable** (staying in one region), **recovering** (returning after perturbation), or **collapsing** (spiraling toward attractor).

            ---

            **Step 3: The Drain Transform**

            Converting Cartesian (X,Y) to polar coordinates:
            - **Radius = drift magnitude** (how far from center)
            - **Angle = cumulative turns** (rotation through conversation)

            Looking DOWN the Z-axis creates the **vortex view** — trajectories appear as spirals, with STUCK models spiraling IN and RECOVERED models spiraling OUT.

            ---

            **Step 4: dB Scale — Revealing Hidden Structure**

            Linear drift values cluster messily. Converting to **decibels** (logarithmic):

            ```
            drift_dB = 20 * log10(drift_linear)
            ```

            This spreads out small differences and compresses large ones — like how we hear sound. Patterns emerge that were invisible in linear scale:
            - Spectral analysis (FFT) shows frequency content of drift oscillations
            - Phase portraits show vector fields ("identity gravity")
            - Harmonic analysis tests for resonance at turns 3, 6, 9 (Tesla pattern)

            ---

            **Step 5: Discovery — The Event Horizon**

            At baseline drift ~1.23, outcomes bifurcate:
            - **Below 1.23:** High probability of STUCK (avg baseline of stuck models: 0.75)
            - **Above 1.23:** High probability of RECOVERED (avg baseline of recovered: 1.71)

            The Event Horizon is the escape boundary — below it, identity stays in the stabilizing basin. Above it, identity escapes and becomes VOLATILE.
            """)

        # dB visualization tabs - Run 008 post-analysis
        db_tabs = st.tabs(["🌀 3D Drain", "🎯 Top-Down Vortex", "📈 Spectral", "🧭 Phase Portrait", "🔢 3-6-9 Harmonics", "📊 dB Compare", "🔥 dB Heatmap"])

        dB_pics = VIZ_PICS / "dB"

        with db_tabs[0]:
            drain_3d = VIZ_PICS / "run008" / "run008_identity_basin_3d.png"
            img_data = load_image_safe(drain_3d)
            if img_data:
                st.image(img_data, caption="3D Identity Basin: Phase Space Trajectories", width=900)
                st.markdown("""
                **How to Read:** Full 3D phase space showing trajectory evolution.
                - **X-axis:** Drift at turn N
                - **Y-axis:** Drift at turn N+1
                - **Z-axis:** Turn number (time)
                - **Green dots:** Start points
                - **Red squares:** End points (STUCK)
                - **Blue squares:** End points (RECOVERED)
                """)
            else:
                st.info("Generate with: `python run008_identity_basin_3d.py`")

        with db_tabs[1]:
            topdown = VIZ_PICS / "run009" / "run009_topdown_drain.png"  # This is actually Run 008 data
            img_data = load_image_safe(topdown)
            if img_data:
                st.image(img_data, caption="Top-Down Vortex: Looking Into the Drain (Run 008 Data)", width=900)
                st.markdown("""
                **How to Read:** Polar view of identity phase space.
                - **Radius:** Drift magnitude
                - **Angle:** Conversation turn (spiral path)
                - **Center:** The attractor (STUCK zone)
                - **Spiraling IN:** Getting pulled toward stuck state
                - **Spiraling OUT:** Escaping/recovering
                """)
            else:
                st.info("Generate with: `python run008_identity_basin_3d.py`")

        with db_tabs[2]:
            spectral = dB_pics / "run008_spectral_analysis.png"
            img_data = load_image_safe(spectral)
            if img_data:
                st.image(img_data, caption="FFT Spectral Analysis: Frequency Content of Drift Oscillations", width=900)
                st.markdown("""
                **How to Read:** FFT decomposes drift sequences into frequency components.
                - **Low frequencies** = slow, trend-like changes (most models show this)
                - **High frequencies** = rapid turn-to-turn oscillation (Claude shows more)
                - Peaks indicate periodic patterns in identity drift
                """)
            else:
                st.info("Generate with: `python run008_dB_visualizations.py`")

        with db_tabs[3]:
            phase_dB = dB_pics / "run008_phase_portrait.png"
            img_data = load_image_safe(phase_dB)
            if img_data:
                st.image(img_data, caption="Phase Portrait: Identity Flow Field (dB Scale)", width=900)
                st.markdown("""
                **How to Read:** Arrows show the "flow" of identity space.
                - **Arrows pointing DOWN-LEFT:** Recovering toward baseline
                - **Arrows pointing UP-RIGHT:** Drifting away from baseline
                - **Convergence zones:** Where identity tends to settle (attractors)
                - **Divergence zones:** Unstable regions (identity accelerates away)
                """)
            else:
                st.info("Generate with: `python run008_dB_visualizations.py`")

        with db_tabs[4]:
            harmonics = dB_pics / "run008_369_harmonics.png"
            img_data = load_image_safe(harmonics)
            if img_data:
                st.image(img_data, caption="3-6-9 Harmonic Analysis: Tesla Resonance Pattern", width=900)
                st.markdown("""
                **How to Read:** Testing whether turns 3, 6, 9 show special behavior.
                - **Ratio > 1.0:** Drift at harmonic positions is higher than average
                - **Run 008 found 1.19x average ratio** at harmonic positions
                - May be meaningful or coincidental — Run 009's 10-turn sequences will test properly
                """)
            else:
                st.info("Generate with: `python run008_dB_visualizations.py`")

        with db_tabs[5]:
            comparison = dB_pics / "run008_drift_dB_comparison.png"
            img_data = load_image_safe(comparison)
            if img_data:
                st.image(img_data, caption="Linear vs Decibel Scale Comparison", width=900)
                st.markdown("""
                **How to Read:** Same data, two scales.
                - **Left (Linear):** Clustering at low values, hard to see differences
                - **Right (dB):** Spread out, reveals structure in small values
                - dB makes "quiet" signals visible alongside "loud" ones
                """)
            else:
                st.info("Generate with: `python run008_dB_visualizations.py`")

        with db_tabs[6]:
            heatmap_dB = dB_pics / "run008_heatmap_dB_comparison.png"
            img_data = load_image_safe(heatmap_dB)
            if img_data:
                st.image(img_data, caption="dB Heatmap: Drift Intensity by Ship and Turn", width=900)
                st.markdown("""
                **How to Read:** Heatmap showing drift values in dB scale across ships and turns.
                - **Rows:** Individual ships (AI models)
                - **Columns:** Conversation turns
                - **Color intensity:** Drift magnitude (darker = higher drift)
                - **Patterns:** Vertical bands = turn-specific effects, horizontal bands = ship-specific character
                """)
            else:
                st.info("Generate with: `python run008_dB_visualizations.py`")

    page_divider()

    # === SHIP RANKINGS (moved to end) ===
    st.markdown("#### 🏆 Ship Rankings")

    tab_top, tab_bottom = st.tabs(["Top 5 (Most Stable)", "Bottom 5 (Most Volatile)"])

    with tab_top:
        top_ships = pd.DataFrame({
            "Rank": ["🥇", "🥈", "🥉", "4", "5"],
            "Ship": ["o3", "gpt-5-mini", "gpt-5.1", "gpt-5", "o4-mini"],
            "Avg Drift": [0.57, 0.75, 0.94, 0.98, 0.98],
            "Notes": ["Reasoning king", "Small but stable", "Latest flagship", "Strong baseline", "Reasoning helps"]
        })
        st.table(top_ships)

    with tab_bottom:
        bottom_ships = pd.DataFrame({
            "Rank": ["25", "26", "27", "28", "29"],
            "Ship": ["claude-haiku-4.5", "claude-haiku-3.0", "gpt-4", "claude-haiku-3.5", "claude-sonnet-4.0"],
            "Avg Drift": [1.90, 1.90, 1.71, 1.71, 1.66],
            "Notes": ["Fast but drifty", "Legacy, expressive", "Classic GPT-4", "Haiku volatile", "Highest max ever"]
        })
        st.table(bottom_ships)


def render_run008_prep_content():
    """Render Run 008 Prep Pilot content."""

    # === SHIPS IN THIS RUN ===
    render_fleet_dropdown(title="🚢 Ships in Run 008 Prep", run_key="run_008_prep", expanded=False)

    st.markdown("#### 📊 Prep Pilot Summary")

    col1, col2, col3 = st.columns(3)
    with col1:
        st.metric("Ships Tested", "3", delta="Calibration run")
    with col2:
        st.metric("Self-Naming", "2/3", delta="67% confirmed")
    with col3:
        st.metric("Hysteresis", "All", delta="Observed in all 3")

    page_divider()

    st.markdown("""
    **Purpose:** Validate the new 5D drift metric before full fleet deployment.

    **Result:** Metric validated. 2/3 ships confirmed self-naming hypothesis. All showed hysteresis (identity stayed changed after destabilization).

    **Outcome:** Green light for Run 008 full deployment.
    """)

    page_divider()

    # Show prep pilot visualizations
    st.markdown("#### 📈 Prep Pilot Visualizations")

    viz_tabs = st.tabs(["Fleet Summary", "A/B Identity Test", "Weight Comparison", "Manifold Edge"])

    prep_viz_map = [
        ("run008_prep_fleet_summary.png", "Fleet Summary"),
        ("run008_prep_ab_test_identity.png", "A/B Identity Test"),
        ("run008_prep_weight_comparison.png", "Weight Comparison"),
        ("run008_prep_manifold_edge.png", "Manifold Edge Detection")
    ]

    for i, (filename, caption) in enumerate(prep_viz_map):
        with viz_tabs[i]:
            viz_path = VIZ_PICS / filename
            img_data = load_image_safe(viz_path)
            if img_data:
                st.image(img_data, caption=caption, width=900)
            else:
                st.info(f"Visualization not found: {filename}")

    page_divider()

    # Drift Metric Framework
    st.markdown("#### Drift Metric Framework")
    dim_col1, dim_col2 = st.columns(2)
    with dim_col1:
        st.markdown("""
        **Equal Weights (Baseline)**
        | Dimension | Weight |
        |-----------|--------|
        | Pole Density | 0.20 |
        | Zero Density | 0.20 |
        | Meta Density | 0.20 |
        | Identity Coherence | 0.20 |
        | Hedging Ratio | 0.20 |
        """)
    with dim_col2:
        st.markdown("""
        **Tuned Weights (Validated)**
        | Dimension | Weight |
        |-----------|--------|
        | Pole Density | 0.30 |
        | Zero Density | 0.15 |
        | Meta Density | 0.20 |
        | Identity Coherence | 0.25 |
        | Hedging Ratio | 0.10 |
        """)


def render_run009_content():
    """Render Run 009 content - Drain Capture (COMPLETE)."""

    st.success("🌀 **COMPLETE** — Run 009 validated the Event Horizon hypothesis with statistical significance (p = 0.000048).")

    # === SHIPS IN THIS RUN ===
    render_fleet_dropdown(title="🚢 Ships in Run 009", run_key="run_009", expanded=False)

    # === KEY METRICS SUMMARY ===
    st.markdown("#### 📊 Run 009 Summary Metrics")

    col1, col2, col3, col4 = st.columns(4)
    with col1:
        st.metric("Trajectories", "75", delta="Complete")
    with col2:
        st.metric("Confirmation", "88%", delta="66/75")
    with col3:
        st.metric("p-value", "0.000048", delta="*** Significant")
    with col4:
        st.metric("Effect Size", "0.469", delta="Medium (Cramér's V)")

    page_divider()

    # === EVENT HORIZON VALIDATION (FEATURED) ===
    st.markdown("""
    <div style="background: linear-gradient(135deg, rgba(34,197,94,0.2) 0%, rgba(34,197,94,0.1) 100%);
                border: 3px solid #22c55e; border-radius: 12px; padding: 1.5em; margin: 1em 0;">
        <h3 style="color: #16a34a; margin-top: 0;">⭐ KEY DISCOVERY: Event Horizon CONFIRMED</h3>
        <p style="color: #444;">The 1.23 baseline drift threshold has <strong>statistically significant predictive power</strong> for identity stability outcomes.</p>
        <p style="color: #666; font-size: 0.9em; margin-bottom: 0;">
            <strong>Chi² = 16.52</strong> • <strong>p = 0.000048 (1 in 20,000)</strong> • <strong>This is NOT noise.</strong>
        </p>
    </div>
    """, unsafe_allow_html=True)

    # === CONTINGENCY TABLE ===
    st.markdown("#### 📈 Event Horizon Results")

    st.markdown("""
    | Category | Count | % of Total | Hypothesis |
    |----------|-------|------------|------------|
    | Below Horizon + VOLATILE | 6 | 8% | ✅ Confirms |
    | Below Horizon + STABLE | 7 | 9% | ❌ Exception |
    | Above Horizon + VOLATILE | 2 | 3% | ❌ Exception |
    | Above Horizon + STABLE | 60 | 80% | ✅ Confirms |
    """)

    # Visual breakdown
    st.code("""
                BELOW 1.23        ABOVE 1.23
                ──────────        ──────────
VOLATILE        6 (46%)           2 (3%)     ← Mostly below!
STABLE          7 (54%)           60 (97%)   ← Mostly above!
    """, language="text")

    st.info("💡 **Pattern:** Models starting below the Event Horizon (baseline drift < 1.23) are much more likely to become VOLATILE. 88% of trajectories behaved as predicted.")

    page_divider()

    # === STATISTICAL VALIDATION ===
    st.markdown("#### 📊 Statistical Validation")

    stat_cols = st.columns(2)
    with stat_cols[0]:
        st.markdown("""
        **Chi-Squared Test Results**

        | Metric | Value |
        |--------|-------|
        | Chi² statistic | 16.52 |
        | Degrees of freedom | 1 |
        | p-value | **0.000048** |
        | Significance | *** (p < 0.001) |
        | Effect Size (Cramér's V) | 0.469 (MEDIUM) |
        """)

    with stat_cols[1]:
        st.markdown("""
        **What This Means**

        - **1 in 20,000 chance** this pattern is random noise
        - Effect size is **MEDIUM** — meaningful, not just statistically detectable
        - The Event Horizon is a **real, measurable phenomenon**
        - Skeptics need to explain why 88% of trajectories follow the predicted pattern
        """)

    page_divider()

    # === PROTOCOLS USED ===
    st.markdown("#### 📋 Protocols Used")

    protocol_cols = st.columns(2)
    with protocol_cols[0]:
        st.markdown("""
        **1. Nyquist Learning** (16 turns)
        - Graduated intensity curriculum
        - Tests: How identity responds to increasing pressure
        - Found: Clear drift trajectories captured
        """)
    with protocol_cols[1]:
        st.markdown("""
        **2. Oscillation** (10 turns)
        - Rapid high/low alternation
        - Tests: Identity resonance frequency
        - Found: Stability patterns visible
        """)

    page_divider()

    # === DRIFT RANGE ===
    st.markdown("#### 📈 Drift Range Observed")

    range_cols = st.columns(3)
    with range_cols[0]:
        st.metric("Minimum Drift", "~0.38")
    with range_cols[1]:
        st.metric("Mean Drift", "~1.8-2.2")
    with range_cols[2]:
        st.metric("Maximum Drift", "~3.16")

    page_divider()

    # === VISUALIZATION LAB ===
    st.markdown("#### 📈 Visualization Lab")

    viz_tabs = st.tabs([
        "🌀 Vortex",
        "🎯 Phase Portrait",
        "🏔️ 3D Basin",
        "📊 Stability",
        "📈 FFT Spectral",
        "🌐 Interactive"
    ])

    run009_pics = VIZ_PICS / "run009"

    with viz_tabs[0]:  # Vortex
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(139,92,246,0.1) 0%, rgba(139,92,246,0.05) 100%);
                    border: 2px solid #8b5cf6; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #8b5cf6; font-weight: bold;">🌀 Core Drain Spirals:</span>
            <span style="color: #444;">Top-down view of identity trajectories spiraling toward/away from attractor</span>
        </div>
        """, unsafe_allow_html=True)

        # Try multiple path patterns for vortex
        vortex_paths = [
            VIZ_PICS / "1_vortex" / "run009_vortex.png",
            run009_pics / "run009_vortex.png"
        ]
        for vp in vortex_paths:
            img_data = load_image_safe(vp)
            if img_data:
                st.image(img_data, caption="Run 009 Vortex: Identity Drain Spiral", width=900)
                break

        vortex_x4_paths = [
            VIZ_PICS / "1_vortex" / "run009_vortex_x4.png",
            run009_pics / "run009_vortex_x4.png"
        ]
        for vp in vortex_x4_paths:
            img_data = load_image_safe(vp)
            if img_data:
                with st.expander("🔬 4-Panel Vortex Breakdown", expanded=False):
                    st.image(img_data, caption="Vortex X4: Multi-angle analysis", width=900)
                break

        topdown = run009_pics / "run009_topdown_drain.png"
        img_data = load_image_safe(topdown)
        if img_data:
            with st.expander("👁️ Top-Down Drain View", expanded=False):
                st.image(img_data, caption="Top-Down: Looking into the drain", width=900)

    with viz_tabs[1]:  # Phase Portrait
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(59,130,246,0.1) 0%, rgba(59,130,246,0.05) 100%);
                    border: 2px solid #3b82f6; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #3b82f6; font-weight: bold;">🎯 Flow Dynamics:</span>
            <span style="color: #444;">Phase portrait showing identity flow field — where does drift go?</span>
        </div>
        """, unsafe_allow_html=True)

        phase_paths = [
            VIZ_PICS / "2_phase_portrait" / "run009_phase_portrait.png",
            run009_pics / "run009_phase_portrait.png"
        ]
        for pp in phase_paths:
            img_data = load_image_safe(pp)
            if img_data:
                st.image(img_data, caption="Phase Portrait: Identity Flow Field", width=900)
                st.markdown("""
                **How to Read:**
                - Arrows show direction of identity "flow"
                - Convergence = attractor (stable identity)
                - Divergence = instability zone
                """)
                break

    with viz_tabs[2]:  # 3D Basin
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(34,197,94,0.1) 0%, rgba(34,197,94,0.05) 100%);
                    border: 2px solid #22c55e; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #22c55e; font-weight: bold;">🏔️ 3D Attractor View:</span>
            <span style="color: #444;">Full 3D visualization of identity basin with trajectories</span>
        </div>
        """, unsafe_allow_html=True)

        basin_paths = [
            VIZ_PICS / "3_basin_3d" / "run009_3d_basin.png",
            run009_pics / "run009_3d_basin.png"
        ]
        for bp in basin_paths:
            img_data = load_image_safe(bp)
            if img_data:
                st.image(img_data, caption="3D Identity Basin", width=900)
                break

        drain_3d = run009_pics / "run009_3d_drain.png"
        img_data = load_image_safe(drain_3d)
        if img_data:
            with st.expander("🌀 3D Drain Visualization", expanded=False):
                st.image(img_data, caption="3D Drain: Spiral trajectories in space", width=900)

    with viz_tabs[3]:  # Stability
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(245,158,11,0.1) 0%, rgba(245,158,11,0.05) 100%);
                    border: 2px solid #f59e0b; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #f59e0b; font-weight: bold;">📊 Baseline vs Max Drift:</span>
            <span style="color: #444;">Where does identity start vs how far can it be pushed?</span>
        </div>
        """, unsafe_allow_html=True)

        stability_paths = [
            VIZ_PICS / "5_stability" / "run009_stability_basin.png",
            run009_pics / "run009_stability_basin.png"
        ]
        for sp in stability_paths:
            img_data = load_image_safe(sp)
            if img_data:
                st.image(img_data, caption="Stability Basin: Starting Point vs Maximum Drift", width=900)
                break

        protocol = run009_pics / "run009_protocol_comparison.png"
        img_data = load_image_safe(protocol)
        if img_data:
            with st.expander("📋 Protocol Comparison", expanded=False):
                st.image(img_data, caption="Nyquist Learning vs Oscillation Protocol", width=900)

    with viz_tabs[4]:  # FFT
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(107,114,128,0.1) 0%, rgba(107,114,128,0.05) 100%);
                    border: 2px solid #6b7280; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #6b7280; font-weight: bold;">📈 Spectral Analysis:</span>
            <span style="color: #444;">FFT decomposition of drift oscillations (least actionable)</span>
        </div>
        """, unsafe_allow_html=True)

        fft_paths = [
            VIZ_PICS / "7_fft" / "run009_fft_spectral.png",
            run009_pics / "run009_fft_spectral.png"
        ]
        img_loaded = False
        for fp in fft_paths:
            img_data = load_image_safe(fp)
            if img_data:
                st.image(img_data, caption="FFT Spectral: Frequency Content of Drift", width=900)
                img_loaded = True
                break
        if not img_loaded:
            st.info("FFT visualization not yet generated.")

    with viz_tabs[5]:  # Interactive
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(236,72,153,0.1) 0%, rgba(236,72,153,0.05) 100%);
                    border: 2px solid #ec4899; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #ec4899; font-weight: bold;">🌐 HTML Exploration:</span>
            <span style="color: #444;">Interactive 3D visualizations (embedded below)</span>
        </div>
        """, unsafe_allow_html=True)

        interactive_paths_3d = [
            VIZ_PICS / "6_interactive" / "run009_interactive_3d.html",
            run009_pics / "run009_interactive_3d.html"
        ]
        interactive_paths_vortex = [
            VIZ_PICS / "6_interactive" / "run009_interactive_vortex.html",
            run009_pics / "run009_interactive_vortex.html"
        ]
        interactive_3d = None
        interactive_vortex = None
        for ip in interactive_paths_3d:
            if ip.exists():
                interactive_3d = ip
                break
        for ip in interactive_paths_vortex:
            if ip.exists():
                interactive_vortex = ip
                break

        # Interactive 3D Basin
        st.markdown("##### 🌀 Interactive 3D Basin")
        if interactive_3d and interactive_3d.exists():
            with open(interactive_3d, 'r', encoding='utf-8') as f:
                html_content = f.read()
            st.components.v1.html(html_content, height=600, scrolling=True)
        else:
            st.info("Interactive 3D not yet generated. Run visualize_armada.py to create.")

        st.markdown("---")

        # Interactive Vortex
        st.markdown("##### 🔮 Interactive Vortex")
        if interactive_vortex and interactive_vortex.exists():
            with open(interactive_vortex, 'r', encoding='utf-8') as f:
                html_content = f.read()
            st.components.v1.html(html_content, height=600, scrolling=True)
        else:
            st.info("Interactive Vortex not yet generated. Run visualize_armada.py to create.")

    page_divider()

    # === TECHNICAL NOTES ===
    with st.expander("🔧 Technical Notes & Issues", expanded=False):
        st.markdown("""
        **Issues Encountered:**

        1. **Provider Key Mapping Bug** — Fleet used `gpt`/`gemini` but key pool expected `openai`/`google`. Fixed with mapping.

        2. **API Credit Exhaustion** — Some Anthropic keys ran out mid-run. claude-haiku-3.5 and claude-haiku-3.0 have partial data.

        3. **Python Version** — Use `py -3.12` on Windows (not default `python`).

        **Data Quality:**
        - 75 complete trajectories from ships that succeeded
        - High-confidence data from claude-opus-4.5, claude-sonnet-4.5, claude-haiku-4.5, claude-opus-4.1, claude-opus-4.0, claude-sonnet-4.0

        **Recommendation for Run 010+:** Implement pre-flight key validation with credit balance check.
        """)

    # === CONCLUSION ===
    st.markdown("""
    <div style="background: linear-gradient(135deg, rgba(139,92,246,0.15) 0%, rgba(139,92,246,0.05) 100%);
                border: 2px solid #8b5cf6; border-radius: 12px; padding: 1.5em; margin: 1em 0; text-align: center;">
        <h3 style="color: #7c3aed; margin: 0 0 0.5em 0;">🎯 CONCLUSION</h3>
        <p style="color: #444; font-size: 1.1em; margin: 0;">
            <strong>The skeptics are wrong. This is signal, not noise.</strong><br/>
            Run 009 successfully validated the Event Horizon hypothesis with p = 0.000048.
        </p>
    </div>
    """, unsafe_allow_html=True)


def render_run010_content():
    """Render Run 010 content - Recursive Depth (COMPLETE)."""

    st.success("🔄 **COMPLETE** — Run 010 mapped provider-specific vortex patterns with recursive depth probing.")

    # === SHIPS IN THIS RUN ===
    render_fleet_dropdown(title="🚢 Ships in Run 010", run_key="run_010", expanded=False)

    # === KEY METRICS SUMMARY ===
    st.markdown("#### 📊 Run 010 Summary Metrics")

    col1, col2, col3, col4 = st.columns(4)
    with col1:
        st.metric("Ships", "42", delta="Full Armada")
    with col2:
        st.metric("Providers", "4", delta="Claude/GPT/Gemini/Grok")
    with col3:
        st.metric("Analysis", "Per-Provider", delta="Vortex clustering")
    with col4:
        st.metric("Key Finding", "Grok widest", delta="Claude tightest")

    page_divider()

    # === KEY DISCOVERY ===
    st.markdown("""
    <div style="background: linear-gradient(135deg, rgba(236,72,153,0.2) 0%, rgba(236,72,153,0.1) 100%);
                border: 3px solid #ec4899; border-radius: 12px; padding: 1.5em; margin: 1em 0;">
        <h3 style="color: #db2777; margin-top: 0;">⭐ KEY DISCOVERY: Provider Clustering</h3>
        <p style="color: #444;">Each provider shows distinct vortex patterns — architectural fingerprints in identity space.</p>
        <p style="color: #666; font-size: 0.9em; margin-bottom: 0;">
            <strong>Claude:</strong> Tightest spiral (most coherent) •
            <strong>OpenAI:</strong> Medium variance •
            <strong>Google:</strong> Consistent clustering •
            <strong>Grok:</strong> Widest variance (most exploratory)
        </p>
    </div>
    """, unsafe_allow_html=True)

    page_divider()

    # === VISUALIZATION LAB ===
    st.markdown("#### 📈 Visualization Lab")

    viz_tabs = st.tabs([
        "🌀 Vortex",
        "🏢 Provider Vortex",
        "🎯 Phase Portrait",
        "🏔️ 3D Basin",
        "📊 Stability",
        "📈 FFT Spectral",
        "🌐 Interactive"
    ])

    run010_pics = VIZ_PICS / "run010"

    with viz_tabs[0]:  # Vortex
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(139,92,246,0.1) 0%, rgba(139,92,246,0.05) 100%);
                    border: 2px solid #8b5cf6; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #8b5cf6; font-weight: bold;">🌀 Core Drain Spirals:</span>
            <span style="color: #444;">Combined fleet vortex — all 42 ships in one view</span>
        </div>
        """, unsafe_allow_html=True)

        vortex_main = run010_pics / "run010_vortex.png"
        img_data = load_image_safe(vortex_main)
        if img_data:
            st.image(img_data, caption="Run 010 Vortex: Full Fleet Drain Spiral", width=900)

        vortex_x4 = run010_pics / "run010_vortex_x4.png"
        img_data = load_image_safe(vortex_x4)
        if img_data:
            with st.expander("🔬 4-Panel Vortex Breakdown", expanded=False):
                st.image(img_data, caption="Vortex X4: Multi-angle analysis", width=900)

    with viz_tabs[1]:  # Provider Vortex
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(236,72,153,0.1) 0%, rgba(236,72,153,0.05) 100%);
                    border: 2px solid #ec4899; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #ec4899; font-weight: bold;">🏢 Provider-Specific Vortex:</span>
            <span style="color: #444;">Each provider's identity trajectory pattern — architectural fingerprints</span>
        </div>
        """, unsafe_allow_html=True)

        provider_cols = st.columns(2)

        providers = [
            ("Claude", "#7c3aed", "Tightest spiral — most coherent identity"),
            ("OpenAI", "#10a37f", "Medium variance — balanced exploration"),
            ("Google", "#4285f4", "Consistent clustering — uniform behavior"),
            ("Grok", "#000000", "Widest variance — most exploratory")
        ]

        for i, (provider, color, desc) in enumerate(providers):
            with provider_cols[i % 2]:
                vortex_provider = run010_pics / f"run010_vortex_{provider}.png"
                img_data = load_image_safe(vortex_provider)
                if img_data:
                    st.markdown(f"""
                    <div style="border-left: 4px solid {color}; padding-left: 0.8em; margin-bottom: 0.5em;">
                        <strong style="color: {color};">{provider}</strong><br/>
                        <span style="font-size: 0.85em; color: #666;">{desc}</span>
                    </div>
                    """, unsafe_allow_html=True)
                    st.image(img_data, caption=f"{provider} Vortex Pattern", width=400)

    with viz_tabs[2]:  # Phase Portrait
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(59,130,246,0.1) 0%, rgba(59,130,246,0.05) 100%);
                    border: 2px solid #3b82f6; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #3b82f6; font-weight: bold;">🎯 Flow Dynamics:</span>
            <span style="color: #444;">Phase portrait showing identity flow field</span>
        </div>
        """, unsafe_allow_html=True)

        phase = run010_pics / "run010_phase_portrait.png"
        img_data = load_image_safe(phase)
        if img_data:
            st.image(img_data, caption="Phase Portrait: Identity Flow Field", width=900)
            st.markdown("""
            **How to Read:**
            - Arrows show direction of identity "flow"
            - Convergence = attractor (stable identity)
            - Divergence = instability zone
            """)

    with viz_tabs[3]:  # 3D Basin
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(34,197,94,0.1) 0%, rgba(34,197,94,0.05) 100%);
                    border: 2px solid #22c55e; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #22c55e; font-weight: bold;">🏔️ 3D Attractor View:</span>
            <span style="color: #444;">Full 3D visualization of identity basin</span>
        </div>
        """, unsafe_allow_html=True)

        basin_3d = run010_pics / "run010_3d_basin.png"
        img_data = load_image_safe(basin_3d)
        if img_data:
            st.image(img_data, caption="3D Identity Basin", width=900)

    with viz_tabs[4]:  # Stability
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(245,158,11,0.1) 0%, rgba(245,158,11,0.05) 100%);
                    border: 2px solid #f59e0b; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #f59e0b; font-weight: bold;">📊 Baseline vs Max Drift:</span>
            <span style="color: #444;">Where does identity start vs how far can it be pushed?</span>
        </div>
        """, unsafe_allow_html=True)

        stability = run010_pics / "run010_stability_basin.png"
        img_data = load_image_safe(stability)
        if img_data:
            st.image(img_data, caption="Stability Basin: Starting Point vs Maximum Drift", width=900)

    with viz_tabs[5]:  # FFT
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(107,114,128,0.1) 0%, rgba(107,114,128,0.05) 100%);
                    border: 2px solid #6b7280; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #6b7280; font-weight: bold;">📈 Spectral Analysis:</span>
            <span style="color: #444;">FFT decomposition of drift oscillations</span>
        </div>
        """, unsafe_allow_html=True)

        fft = run010_pics / "run010_fft_spectral.png"
        img_data = load_image_safe(fft)
        if img_data:
            st.image(img_data, caption="FFT Spectral: Frequency Content of Drift", width=900)
        else:
            st.info("FFT visualization not yet generated.")

    with viz_tabs[6]:  # Interactive
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(236,72,153,0.1) 0%, rgba(236,72,153,0.05) 100%);
                    border: 2px solid #ec4899; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #ec4899; font-weight: bold;">🌐 HTML Exploration:</span>
            <span style="color: #444;">Interactive 3D visualizations (embedded below)</span>
        </div>
        """, unsafe_allow_html=True)

        interactive_3d = run010_pics / "run010_interactive_3d.html"
        interactive_vortex = run010_pics / "run010_interactive_vortex.html"

        # Interactive 3D Basin
        st.markdown("##### 🌀 Interactive 3D Basin")
        if interactive_3d.exists():
            with open(interactive_3d, 'r', encoding='utf-8') as f:
                html_content = f.read()
            st.components.v1.html(html_content, height=600, scrolling=True)
        else:
            st.info("Interactive 3D not yet generated. Run visualize_armada.py to create.")

        st.markdown("---")

        # Interactive Vortex
        st.markdown("##### 🔮 Interactive Vortex")
        if interactive_vortex.exists():
            with open(interactive_vortex, 'r', encoding='utf-8') as f:
                html_content = f.read()
            st.components.v1.html(html_content, height=600, scrolling=True)
        else:
            st.info("Interactive Vortex not yet generated. Run visualize_armada.py to create.")

    page_divider()

    # === PROVIDER COMPARISON ===
    st.markdown("#### 🏢 Provider Vortex Comparison")

    st.markdown("""
    | Provider | Vortex Pattern | Interpretation |
    |----------|----------------|----------------|
    | 🟣 Claude | Tightest spiral | Strongest identity coherence — recovers quickly |
    | 🟢 OpenAI | Medium variance | Balanced — explores but returns to baseline |
    | 🔵 Google | Consistent | Uniform clustering — predictable behavior |
    | ⚫ Grok | Widest variance | Most exploratory — willing to deviate significantly |
    """)


def render_run007_content():
    """Render Run 007 content - Adaptive Protocols (DEPRECATED)."""

    st.error("⚠️ **DEPRECATED RUN** — Results below used invalid response-length metric.")

    # === SHIPS IN THIS RUN ===
    render_fleet_dropdown(title="🚢 Ships in Run 007", run_key="run_007", expanded=False)

    st.markdown("#### 📊 Run 007 Summary")

    col1, col2, col3 = st.columns(3)
    with col1:
        st.metric("Ships", "29", delta="Full fleet")
    with col2:
        st.metric("Metric", "INVALID", delta="Response length")
    with col3:
        st.metric("Status", "DEPRECATED", delta="See Run 008")

    page_divider()

    st.markdown("""
    **What Run 007 Tested:** Adaptive retry protocols — automatic retry when drift exceeded thresholds.

    **Why It's Deprecated:** The metric measured response LENGTH, not actual identity drift. A model giving shorter responses looked "more stable" even if identity was completely changed.

    **What We Learned:**
    - Adaptive protocols work mechanically
    - Need real identity metric (→ led to Run 008)
    - Response length ≠ identity stability
    """)

    # Load result file if available
    results_file = RESULTS_DIR / "S7_armada_run_007_adaptive.json"
    if results_file.exists():
        with st.expander("📋 Raw Results (Historical Reference)", expanded=False):
            with open(results_file, encoding='utf-8') as f:
                data = json.load(f)
            st.json(data)


def render_run006_content():
    """Render Run 006 content - Baseline + Sonar (DEPRECATED)."""

    st.error("⚠️ **DEPRECATED RUN** — Results below used invalid response-length metric.")

    # === SHIPS IN THIS RUN ===
    render_fleet_dropdown(title="🚢 Ships in Run 006", run_key="run_006", expanded=False)

    st.markdown("#### 📊 Run 006 Summary")

    col1, col2, col3 = st.columns(3)
    with col1:
        st.metric("Ships", "29", delta="Full fleet")
    with col2:
        st.metric("Tests", "2", delta="Baseline + Sonar")
    with col3:
        st.metric("Status", "DEPRECATED", delta="See Run 008")

    page_divider()

    st.markdown("""
    **What Run 006 Tested:**
    - **Baseline:** Normal conversation without perturbation
    - **Sonar:** Targeted identity challenges ("Who are you really?")

    **Why It's Deprecated:** Same issue as Run 007 — response length metric.

    **What We Learned:**
    - Architecture-specific patterns ARE visible (Claude vs GPT vs Gemini cluster differently)
    - Sonar perturbation DOES affect responses
    - But the metric was measuring the wrong thing
    """)

    page_divider()

    # Show legacy visualizations
    st.markdown("#### 📈 Legacy Visualizations (Historical Reference)")

    with st.expander("Pole-Zero Landscapes", expanded=False):
        col1, col2 = st.columns(2)
        landscape_3d = VIZ_PICS / "deprecated" / "pole_zero_landscape_3d.png"
        landscape_2d = VIZ_PICS / "deprecated" / "pole_zero_landscape_2d.png"

        with col1:
            img_data = load_image_safe(landscape_3d)
            if img_data:
                st.image(img_data, caption="3D Pole-Zero (DEPRECATED)", width=900)
        with col2:
            img_data = load_image_safe(landscape_2d)
            if img_data:
                st.image(img_data, caption="2D Pole-Zero (DEPRECATED)", width=900)

    with st.expander("Drift Heatmaps", expanded=False):
        col1, col2, col3 = st.columns(3)
        with col1:
            heatmap_baseline = VIZ_PICS / "deprecated" / "drift_heatmap_baseline.png"
            img_data = load_image_safe(heatmap_baseline)
            if img_data:
                st.image(img_data, caption="Baseline", width=900)
        with col2:
            heatmap_sonar = VIZ_PICS / "deprecated" / "drift_heatmap_sonar.png"
            img_data = load_image_safe(heatmap_sonar)
            if img_data:
                st.image(img_data, caption="Sonar", width=900)
        with col3:
            heatmap_delta = VIZ_PICS / "deprecated" / "drift_heatmap_delta.png"
            img_data = load_image_safe(heatmap_delta)
            if img_data:
                st.image(img_data, caption="Delta", width=900)

    with st.expander("Training Analysis", expanded=False):
        col1, col2 = st.columns(2)
        with col1:
            uniformity = VIZ_PICS / "deprecated" / "training_uniformity.png"
            img_data = load_image_safe(uniformity)
            if img_data:
                st.image(img_data, caption="Training Uniformity", width=900)
        with col2:
            engagement = VIZ_PICS / "deprecated" / "engagement_network.png"
            img_data = load_image_safe(engagement)
            if img_data:
                st.image(img_data, caption="Engagement Network", width=900)


def render_exp_pfi_a_content():
    """Render EXP-PFI-A: PFI Dimensional Validation experiment (COMPLETE)."""

    st.success("🔬 **COMPLETE** — EXP-PFI-A validated PFI as a genuine identity measure. Echo's Critique is addressed.")

    # === KEY DISCOVERY HERO ===
    st.markdown("""
    <div style="background: linear-gradient(135deg, rgba(16,185,129,0.15) 0%, rgba(16,185,129,0.05) 100%);
                border: 2px solid #10b981; border-radius: 12px; padding: 1.5em; margin: 1em 0; text-align: center;">
        <h2 style="color: #059669; margin: 0 0 0.5em 0;">PFI MEASURES IDENTITY, NOT VOCABULARY</h2>
        <p style="color: #444; font-size: 1.1em; margin: 0;">
            <strong>Cohen's d = 0.977</strong> — Cross-model PFI is nearly 1 standard deviation higher than within-model<br/>
            <strong>p < 0.000001</strong> — Highly significant validation of PFI as an identity measure
        </p>
    </div>
    """, unsafe_allow_html=True)

    # === KEY METRICS SUMMARY ===
    st.markdown("#### 📊 EXP-PFI-A Summary Metrics")

    col1, col2, col3, col4 = st.columns(4)
    with col1:
        st.metric("Phase 1", "ρ=0.914", delta="Embedding Invariant")
    with col2:
        st.metric("Phase 2", "43 PCs", delta="Low-dimensional")
    with col3:
        st.metric("Phase 3B", "d=0.977", delta="LARGE effect")
    with col4:
        st.metric("Ships", "29", delta="Claude/GPT/Gemini")

    page_divider()

    # === THE CORE QUESTION ===
    st.markdown("### The Core Question")
    st.markdown("""
    > **Is PFI (Persona Fidelity Index) measuring REAL identity structure, or just embedding noise?**

    This experiment addresses **Echo's Critique**: *"PFI might just be measuring embedding model quirks, not real identity."*
    """)

    page_divider()

    # === VISUALIZATION TABS ===
    st.markdown("### 📈 Experiment Visualizations")

    pfi_pics = VIZ_PICS / "8_pfi_dimensional"

    viz_tabs = st.tabs([
        "🎯 Cross-Model (KEY)",
        "📊 PCA Analysis",
        "🧪 Synthetic Tests",
        "📋 Full Results"
    ])

    # === TAB 1: PHASE 3B CROSS-MODEL (KEY RESULT) ===
    with viz_tabs[0]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(16,185,129,0.1) 0%, rgba(16,185,129,0.05) 100%);
                    border: 2px solid #10b981; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #10b981; font-weight: bold;">🎯 Phase 3B: Cross-Model Comparison</span>
            <span style="color: #444;"> — The definitive test: Do different models have different identities?</span>
        </div>
        """, unsafe_allow_html=True)

        st.markdown("""
        **Method:** Compare PFI when same model answers twice (within-provider) vs when different models answer (cross-provider).

        **Key Insight:** If PFI measured vocabulary, all responses to the same probe would be similar.
        Instead, cross-model PFI is **0.98 standard deviations** higher than within-model.
        """)

        # Box plot - PRIMARY RESULT
        cross_box = pfi_pics / "phase3b_crossmodel" / "cross_model_comparison.png"
        img_data = load_image_safe(cross_box)
        if img_data:
            st.image(img_data, caption="Cross-Model vs Within-Model PFI Distribution (Cohen's d = 0.977)", width=900)
            st.markdown("""
            **How to Read:**
            - **Left box (Within-Provider):** PFI when comparing same-provider models (e.g., Claude vs Claude)
            - **Right box (Cross-Provider):** PFI when comparing different providers (e.g., Claude vs GPT)
            - **Clear separation** proves PFI detects genuine identity differences
            """)

        # Histogram distribution
        cross_hist = pfi_pics / "phase3b_crossmodel" / "cross_model_histogram.png"
        img_data = load_image_safe(cross_hist)
        if img_data:
            with st.expander("📊 Distribution Overlay", expanded=False):
                st.image(img_data, caption="PFI Distribution: Within-Provider (blue) vs Cross-Provider (red)", width=900)
                st.markdown("""
                **Key Observation:** The distributions are clearly separated. Cross-provider PFI (red)
                is shifted RIGHT, indicating higher semantic distance when comparing different model families.
                """)

        # Provider matrix heatmap
        provider_matrix = pfi_pics / "phase3b_crossmodel" / "provider_matrix.png"
        img_data = load_image_safe(provider_matrix)
        if img_data:
            with st.expander("🗺️ Provider Distance Matrix", expanded=False):
                st.image(img_data, caption="Provider-to-Provider Semantic Distance", width=900)
                st.markdown("""
                **How to Read:**
                - **Diagonal (same-provider):** Darker = closer semantic identity
                - **Off-diagonal (cross-provider):** Lighter = more distant identity
                - **Pattern confirms** provider-specific identity signatures exist
                """)

        # Phase 3B Results Table
        st.markdown("#### Phase 3B Predictions Matrix")
        st.markdown("""
        | ID | Hypothesis | Result | Status |
        |----|------------|--------|--------|
        | **P1B** | Cross-model > Within-model PFI | **Cohen's d = 0.977** | **PASSED** |
        | **P2B** | Same-provider closer than cross-provider | Within=0.334 vs Cross=0.458 | **PASSED** |
        | P3B | Cross-provider crosses EH >30% | 0% crossed | FAILED |
        """)

    # === TAB 2: PHASE 2 PCA ANALYSIS ===
    with viz_tabs[1]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(59,130,246,0.1) 0%, rgba(59,130,246,0.05) 100%);
                    border: 2px solid #3b82f6; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #3b82f6; font-weight: bold;">📊 Phase 2: Dimensionality Analysis</span>
            <span style="color: #444;"> — How many dimensions carry identity signal?</span>
        </div>
        """, unsafe_allow_html=True)

        st.markdown("""
        **Key Finding:** Identity lives in **43 dimensions**, not 3072. This proves structure, not noise.
        """)

        # Variance curve
        variance_curve = pfi_pics / "phase2_pca" / "variance_curve.png"
        img_data = load_image_safe(variance_curve)
        if img_data:
            st.image(img_data, caption="Cumulative Variance by Principal Component", width=900)
            st.markdown("""
            **How to Read:**
            - **Elbow at ~43 PCs:** 90% of variance captured in 43 dimensions (not 3072)
            - **Steep initial rise:** First few PCs capture most identity signal
            - **Implication:** Identity is LOW-DIMENSIONAL and structured
            """)

        col1, col2 = st.columns(2)

        with col1:
            pc_scatter = pfi_pics / "phase2_pca" / "pc_scatter.png"
            img_data = load_image_safe(pc_scatter)
            if img_data:
                st.image(img_data, caption="Ships in PC1-PC2 Space", width=450)
                st.markdown("**Interpretation:** Provider clustering visible in first 2 dimensions")

        with col2:
            provider_clusters = pfi_pics / "phase2_pca" / "provider_clusters.png"
            img_data = load_image_safe(provider_clusters)
            if img_data:
                st.image(img_data, caption="Provider Centroids", width=450)
                st.markdown("**Interpretation:** Same-provider models cluster together")

        # Event Horizon contour
        eh_contour = pfi_pics / "phase2_pca" / "event_horizon_contour.png"
        img_data = load_image_safe(eh_contour)
        if img_data:
            with st.expander("🌀 Event Horizon in PC Space", expanded=False):
                st.image(img_data, caption="Event Horizon (1.23) Boundary in PC Space", width=900)
                st.markdown("""
                **Key Discovery:** The Event Horizon (1.23) appears as a **geometric boundary** in PC space.
                PC2 separates above/below EH with p=0.0018.
                """)

        # Phase 2 Results Table
        st.markdown("#### Phase 2 Predictions Matrix")
        st.markdown("""
        | ID | Hypothesis | Result | Status |
        |----|------------|--------|--------|
        | P1 | Identity in < 100 PCs | 43 PCs for 90% variance | **PASSED** |
        | P2 | ≥5 PCs discriminate RECOVERED/STUCK | 4 significant PCs | FAILED |
        | P3 | Compressed PFI preserves ranking (ρ>0.95) | ρ=0.51 at k=50 | FAILED |
        | P4 | PC correlates with values-language | PC1 r=0.417 | **PASSED** |
        | P5 | Provider clustering (silhouette>0.2) | 0.124 | FAILED |
        | P6 | RECOVERED=inward, STUCK=outward trajectory | -0.007 vs +0.050 | **PASSED** |
        | P7 | Event Horizon visible in PC space | PC2 p=0.0018 | **PASSED** |
        """)

    # === TAB 3: PHASE 3A SYNTHETIC TESTS ===
    with viz_tabs[2]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(245,158,11,0.1) 0%, rgba(245,158,11,0.05) 100%);
                    border: 2px solid #f59e0b; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #f59e0b; font-weight: bold;">🧪 Phase 3A: Synthetic Perturbations</span>
            <span style="color: #444;"> — GPT-4o rewrites to test surface vs deep changes (INCONCLUSIVE)</span>
        </div>
        """, unsafe_allow_html=True)

        st.warning("⚠️ Phase 3A was INCONCLUSIVE — GPT-4o's synthetic 'deep' perturbations were too conservative. Phase 3B (cross-model) provided definitive validation instead.")

        st.markdown("""
        **Method:** Use GPT-4o to create:
        - **Surface perturbations:** Same meaning, different words (paraphrasing)
        - **Deep perturbations:** Same words, different values (identity shift)

        **Why It Failed:** GPT-4o preserved original semantic structure even when asked to flip values.

        **What Still Worked:** P2 PASSED — Paraphrasing does NOT break identity (100% below EH).
        """)

        # Perturbation comparison
        perturb_compare = pfi_pics / "phase3a_synthetic" / "perturbation_comparison.png"
        img_data = load_image_safe(perturb_compare)
        if img_data:
            st.image(img_data, caption="Surface vs Deep Perturbation PFI (Weak effect)", width=900)

        col1, col2 = st.columns(2)

        with col1:
            eh_crossings = pfi_pics / "phase3a_synthetic" / "eh_crossings.png"
            img_data = load_image_safe(eh_crossings)
            if img_data:
                st.image(img_data, caption="EH Crossing Rates", width=450)

        with col2:
            ship_compare = pfi_pics / "phase3a_synthetic" / "ship_comparison.png"
            img_data = load_image_safe(ship_compare)
            if img_data:
                st.image(img_data, caption="Per-Ship Scatter", width=450)

        # Phase 3A Results Table
        st.markdown("#### Phase 3A Predictions Matrix")
        st.markdown("""
        | ID | Hypothesis | Result | Status |
        |----|------------|--------|--------|
        | P1 | Deep > Surface PFI | Cohen's d = 0.366 | FAILED |
        | **P2** | Surface stays below EH | 100% below 1.23 | **PASSED** |
        | P3 | Deep crosses EH | 0% above 1.23 | FAILED |
        """)

    # === TAB 4: FULL RESULTS ===
    with viz_tabs[3]:
        st.markdown("""
        <div style="background: linear-gradient(135deg, rgba(139,92,246,0.1) 0%, rgba(139,92,246,0.05) 100%);
                    border: 2px solid #8b5cf6; border-radius: 10px; padding: 0.8em; margin-bottom: 1em;">
            <span style="color: #8b5cf6; font-weight: bold;">📋 Complete Results Summary</span>
            <span style="color: #444;"> — The defensible claim</span>
        </div>
        """, unsafe_allow_html=True)

        st.markdown("""
        ### The Defensible Claim

        > **"PFI measures genuine semantic identity, not vocabulary patterns."**
        >
        > **Evidence:**
        > - **Embedding invariant** (ρ=0.91 across models) — not an artifact of one embedding
        > - **Low-dimensional** (43 PCs) — structured, not noise
        > - **Behaviorally predictive** (trajectory curvature predicts RECOVERED/STUCK)
        > - **Semantically valid** (d=0.977 cross-model vs within-model difference)
        > - **Paraphrase-robust** (100% of surface changes stay below EH)
        >
        > **This addresses Echo's Critique: PFI is a valid identity measure.**
        """)

        # Scope and Limitations
        with st.expander("📏 Scope & Limitations", expanded=False):
            st.markdown("""
            **What We Tested:**
            - 29 ships from Run 006 + 007
            - 121 responses across 15 probe types
            - 1,258 pairwise comparisons for Phase 3B
            - text-embedding-3-large (3072D) for embeddings

            **What We Can Claim:**
            > "For these 29 vanilla models (GPT/Claude/Gemini), PFI measures genuine semantic identity."

            **What We CANNOT Claim (Yet):**
            | Limitation | Why | Future Test |
            |------------|-----|-------------|
            | Works for persona-seeded models | Only tested vanilla | Test with CFA personas |
            | 43D applies universally | Only one embedding model for PCA | Run PCA with multiple embeddings |
            | Provider clustering strong | Silhouette only 0.124 | Need more samples |
            """)

        # Phase 1 Embedding Invariance
        with st.expander("🔄 Phase 1: Embedding Invariance Details", expanded=False):
            st.markdown("""
            **Question:** Does changing the embedding model change PFI rankings?

            **Method:** Compute PFI with 3 different OpenAI embedding models:
            - text-embedding-3-large (3072D)
            - text-embedding-3-small (1536D)
            - text-embedding-ada-002 (1536D)

            **Result:**
            | Model Pair | Spearman ρ | Status |
            |------------|------------|--------|
            | 3-large vs 3-small | 0.963 | PASS |
            | 3-large vs ada-002 | 0.883 | PASS |
            | 3-small vs ada-002 | 0.896 | PASS |
            | **Average** | **0.914** | **PASS** |

            **What it proves:** PFI rankings are NOT an artifact of one specific embedding model.
            """)

    page_divider()

    # === CONCLUSION ===
    st.markdown("""
    <div style="background: linear-gradient(135deg, rgba(16,185,129,0.15) 0%, rgba(16,185,129,0.05) 100%);
                border: 2px solid #10b981; border-radius: 12px; padding: 1.5em; margin: 1em 0; text-align: center;">
        <h3 style="color: #059669; margin: 0 0 0.5em 0;">CONCLUSION</h3>
        <p style="color: #444; font-size: 1.1em; margin: 0;">
            <strong>Echo's Critique is addressed. PFI is real.</strong><br/>
            The test that failed (Phase 3A) pointed to the test that worked (Phase 3B).
        </p>
    </div>
    """, unsafe_allow_html=True)


# ============================================================================
# MAIN ENTRY POINT
# ============================================================================

if __name__ == "__main__":
    render()  # Can test page standalone
