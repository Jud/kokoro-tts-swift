#!/usr/bin/env python3
"""CoreML export harness for Kokoro.

Exports dynamic model, compares against patched PyTorch (same model) for
quantitative metrics, and generates vanilla PyTorch audio for listening.

Usage:
    .venv/bin/python scripts/stage_harness.py
"""
import json
import os
import shutil
import subprocess
import sys
import tempfile
import threading
import time

import numpy as np
import soundfile as sf
import torch
import torch.nn as nn

# pack_padded_sequence no-op (needed for tracing AND patched PyTorch reference)
nn.utils.rnn.pack_padded_sequence = lambda x, lengths, **kw: x
nn.utils.rnn.pad_packed_sequence = lambda x, **kw: (x, None)

import coremltools as ct

SCRIPT_DIR = os.path.dirname(os.path.abspath(__file__))
sys.path.insert(0, SCRIPT_DIR)

from reference import patch_sinegen_for_export
from export_coreml import (
    KokoroModelA, KokoroModelB, NUM_HARMONICS, S_CONTENT_DIM,
    SAMPLES_PER_FRAME, _tokenize, load_kokoro_model,
)

# ---------------------------------------------------------------------------
# Config
# ---------------------------------------------------------------------------
THRESH_CORR = 0.99
THRESH_SPIKES = 50
THRESH_SPEED_MS = 300

BENCHMARK_VOICE = "af_heart"
AUDIO_VOICES = ["af_heart", "af_bella", "am_adam", "bf_emma", "bm_daniel"]

TEST_SENTENCES = {
    "short": "Hello world.",
    "medium": "She sells seashells by the seashore, and the shells she sells are surely seashells.",
    "long": "The quick brown fox jumps over the lazy dog. She sells seashells by the seashore. "
            "In a hole in the ground there lived a hobbit, not a nasty dirty wet hole filled with worms.",
}

# ---------------------------------------------------------------------------
# Helpers
# ---------------------------------------------------------------------------

def _repo_root():
    return os.path.dirname(SCRIPT_DIR)


def _git_short_hash():
    try:
        return subprocess.check_output(
            ["git", "rev-parse", "--short", "HEAD"],
            stderr=subprocess.DEVNULL, text=True, cwd=_repo_root(),
        ).strip()
    except Exception:
        return "unknown"

# ---------------------------------------------------------------------------
# PyTorch reference (patched model — same codepath as CoreML export)
# ---------------------------------------------------------------------------

def load_patched_model():
    """Load model with same patches as export (for quantitative comparison)."""
    pipeline, model = load_kokoro_model()
    set_phases_fn = patch_sinegen_for_export(model)
    return pipeline, model, set_phases_fn


def run_patched_pytorch(model, set_phases_fn, token_ids, ref_s):
    """Run patched PyTorch with dynamic frames (same as CoreML export)."""
    import torch.nn.functional as F

    n = len(token_ids)
    max_audio = ((n * 1600 + 599) // 600) * 600

    fe = KokoroModelA(model, n, max_audio, set_phases_fn)
    fe.eval()
    be = KokoroModelB(model)
    be.eval()

    ids = torch.tensor([token_ids], dtype=torch.long)
    mask = torch.ones(1, n, dtype=torch.long)

    with torch.no_grad():
        asr, F0, N, har, alen_t, _ = fe(
            ids, mask, ref_s, torch.tensor([1.0]), torch.zeros(1, NUM_HARMONICS))
        audio = be(asr, F0, N, ref_s[:, :S_CONTENT_DIM], har)

    alen = int(alen_t.flatten()[0].item())
    return audio.squeeze().detach().numpy()[:alen]

# ---------------------------------------------------------------------------
# Vanilla PyTorch reference (subprocess — no patches)
# ---------------------------------------------------------------------------

def generate_vanilla_reference(voice, sentences, output_dir):
    os.makedirs(output_dir, exist_ok=True)
    result = subprocess.run(
        [sys.executable, os.path.join(SCRIPT_DIR, "gen_reference.py"),
         "--output-dir", output_dir, "--voice", voice,
         "--sentences-json", json.dumps(sentences)],
        capture_output=True, text=True, cwd=SCRIPT_DIR, timeout=300,
    )
    if result.returncode != 0:
        raise RuntimeError(f"Reference failed: {result.stderr[-300:]}")

# ---------------------------------------------------------------------------
# Export (subprocess)
# ---------------------------------------------------------------------------

def export_dynamic(output_dir):
    result = subprocess.run(
        [sys.executable, os.path.join(SCRIPT_DIR, "export_coreml.py"),
         "--output-dir", output_dir],
        capture_output=True, text=True, cwd=SCRIPT_DIR, timeout=600,
    )
    if result.returncode != 0:
        raise RuntimeError(f"Export failed: {result.stderr[-300:]}")

# ---------------------------------------------------------------------------
# CoreML inference
# ---------------------------------------------------------------------------

def run_coreml(fe_model, be_model, token_ids, ref_s):
    n = len(token_ids)
    ref_s_np = ref_s.detach().numpy().astype(np.float32)

    fe_out = fe_model.predict({
        "input_ids": np.array([token_ids], dtype=np.int32),
        "attention_mask": np.ones((1, n), dtype=np.int32),
        "ref_s": ref_s_np,
        "speed": np.array([1.0], dtype=np.float32),
        "random_phases": np.zeros((1, NUM_HARMONICS), dtype=np.float32),
    })

    alen = int(fe_out['audio_length_samples'].flatten()[0])

    result = {}
    def _run_be():
        feed = {
            'asr': fe_out['asr'].astype(np.float32),
            'F0_pred': fe_out['F0_pred'].astype(np.float32),
            'N_pred': fe_out['N_pred'].astype(np.float32),
            's_content': ref_s_np[:, :S_CONTENT_DIM],
            'har': fe_out['har'].astype(np.float32),
        }
        be_model.predict(feed)  # warmup
        t0 = time.time()
        result['out'] = be_model.predict(feed)
        result['speed'] = time.time() - t0

    t = threading.Thread(target=_run_be)
    t.start()
    t.join()

    audio = result['out']['audio'].flatten()[:alen]
    return audio, result['speed']

# ---------------------------------------------------------------------------
# Comparison
# ---------------------------------------------------------------------------

def compare(py_audio, cm_audio):
    ml = min(len(py_audio), len(cm_audio))
    if ml == 0:
        return {"corr": 0, "p999": 0, "spike_rate": 0}
    py = py_audio[:ml].astype(np.float64)
    cm = cm_audio[:ml].astype(np.float64)
    corr = float(np.corrcoef(py, cm)[0, 1]) if np.std(py) > 1e-10 else 0.0
    abs_diff = np.abs(py - cm)
    p999 = float(np.percentile(abs_diff, 99.9))
    spikes = int(np.sum(abs_diff > 0.05))
    spike_rate = spikes / (ml / 24000.0) if ml > 0 else 0
    return {"corr": corr, "p999": p999, "spike_rate": spike_rate}

# ---------------------------------------------------------------------------
# Output
# ---------------------------------------------------------------------------

def print_results(results):
    w = 62
    print(f"\n{'='*w}")
    print(f"{'Test':<24} {'':>4} {'Corr':>7} {'p99.9':>7} {'Spk/s':>6} {'Speed':>6}")
    print(f"{'-'*w}")
    for r in results:
        name = r["name"]
        if r.get("error"):
            print(f"{name:<24} FAIL {'':>7} {'':>7} {'':>6} {'':>6}")
            continue
        corr, p999, sr = r["corr"], r["p999"], r["spike_rate"]
        speed_ms = r["speed_ms"]
        flag = "PASS" if corr >= THRESH_CORR and sr <= THRESH_SPIKES and speed_ms <= THRESH_SPEED_MS else "FAIL"
        print(f"{name:<24} {flag:>4} {corr:>7.4f} {p999:>7.4f} {sr:>6.0f} {speed_ms:>4.0f}ms")
    print(f"{'='*w}")

# ---------------------------------------------------------------------------
# Main
# ---------------------------------------------------------------------------

def main():
    commit = _git_short_hash()
    audio_dir = os.path.join(_repo_root(), "research", "audio", commit)
    os.makedirs(audio_dir, exist_ok=True)

    # Load patched model for quantitative PyTorch reference
    print("Loading model...")
    pipeline, model, set_phases_fn = load_patched_model()

    # Export dynamic models (subprocess)
    export_dir = tempfile.mkdtemp(prefix="harness_")
    print("Exporting dynamic model...")
    try:
        export_dynamic(export_dir)
    except Exception as e:
        print(f"Export failed: {e}")
        return

    fe_path = os.path.join(export_dir, "kokoro_frontend.mlpackage")
    be_path = os.path.join(export_dir, "kokoro_backend.mlpackage")

    # Load CoreML models
    fe_model = ct.models.MLModel(fe_path, compute_units=ct.ComputeUnit.CPU_ONLY)
    be_loaded = {}
    def _load_be():
        be_loaded['m'] = ct.models.MLModel(be_path, compute_units=ct.ComputeUnit.ALL)
    t = threading.Thread(target=_load_be); t.start(); t.join()
    be_model = be_loaded['m']

    # Generate vanilla PyTorch audio for listening (subprocess)
    vanilla_dir = tempfile.mkdtemp(prefix="vanilla_")
    print("Generating vanilla reference...")
    try:
        generate_vanilla_reference(BENCHMARK_VOICE, TEST_SENTENCES, vanilla_dir)
    except Exception as e:
        print(f"Vanilla reference failed: {e}")

    # Benchmark: patched PyTorch vs CoreML (quantitative)
    results = []
    voice_pack = pipeline.load_voice(BENCHMARK_VOICE)

    for label, text in TEST_SENTENCES.items():
        token_ids = _tokenize(text, pipeline)
        n = len(token_ids)
        ref_s = voice_pack[n]

        try:
            # Patched PyTorch reference (same model, same inputs)
            py_audio = run_patched_pytorch(model, set_phases_fn, token_ids, ref_s)

            # CoreML
            cm_audio, speed_s = run_coreml(fe_model, be_model, token_ids, ref_s)

            metrics = compare(py_audio, cm_audio)
            results.append({
                "name": label,
                "corr": metrics["corr"],
                "p999": metrics["p999"],
                "spike_rate": metrics["spike_rate"],
                "speed_ms": speed_s * 1000,
            })

            # Save patched PyTorch + CoreML audio
            sf.write(os.path.join(audio_dir, f"{BENCHMARK_VOICE}_{label}_patched_pytorch.wav"),
                     py_audio, 24000)
            sf.write(os.path.join(audio_dir, f"{BENCHMARK_VOICE}_{label}_coreml.wav"),
                     cm_audio, 24000)

            # Copy vanilla PyTorch audio if available
            vanilla_path = os.path.join(vanilla_dir, f"{label}.wav")
            if os.path.exists(vanilla_path):
                shutil.copy(vanilla_path,
                    os.path.join(audio_dir, f"{BENCHMARK_VOICE}_{label}_vanilla_pytorch.wav"))

        except Exception as e:
            results.append({"name": label, "error": str(e)[:80]})

    # Worst case
    valid = [r for r in results if "error" not in r]
    if valid:
        results.append({
            "name": "WORST",
            "corr": min(r["corr"] for r in valid),
            "p999": max(r["p999"] for r in valid),
            "spike_rate": max(r["spike_rate"] for r in valid),
            "speed_ms": max(r["speed_ms"] for r in valid),
        })

    # Extra voices (CoreML only)
    for voice in AUDIO_VOICES:
        if voice == BENCHMARK_VOICE:
            continue
        vp = pipeline.load_voice(voice)
        for label, text in TEST_SENTENCES.items():
            phonemes, _ = pipeline.g2p(text)
            raw = list(filter(lambda i: i is not None,
                map(lambda p: model.vocab.get(p), phonemes)))
            token_ids = [0] + raw + [0]
            ref_s = vp[len(token_ids)]
            try:
                cm_audio, _ = run_coreml(fe_model, be_model, token_ids, ref_s)
                sf.write(os.path.join(audio_dir, f"{voice}_{label}_coreml.wav"),
                         cm_audio, 24000)
            except Exception:
                pass

    print_results(results)
    print(f"\nAudio saved to: {audio_dir}")

    shutil.rmtree(export_dir, ignore_errors=True)
    shutil.rmtree(vanilla_dir, ignore_errors=True)


if __name__ == "__main__":
    main()
