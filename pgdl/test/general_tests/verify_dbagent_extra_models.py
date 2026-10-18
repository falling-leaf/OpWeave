#!/usr/bin/env python3
"""

Verify that dbagent calls reader_decoder.py and potentially other models.

This explains the ~21s execution time vs ~3.5s for pure Python inference.
"""
import os
import sys
sys.path.insert(0, os.path.join(os.path.dirname(os.path.abspath(__file__)), '..'))

import os, sys, time, subprocess as sp
import numpy as np
import torch
import psycopg2

MODEL_DIR = os.path.join(os.path.dirname(os.path.dirname(os.path.abspath(__file__))), "morphingdb_test", "models")
TOOLS_DIR = os.path.join(os.path.dirname(os.path.dirname(os.path.abspath(__file__))), "tools")
DB_CONFIG = {"dbname": "postgres", "host": "localhost", "port": "5432", "user": "why", "password": "123456"}


def load_mvec_vectors(n):
    conn = psycopg2.connect(**DB_CONFIG)
    cur = conn.cursor()
    cur.execute("SELECT get_mvec_data(reasoning_vec) FROM reasoning_vector_test ORDER BY id LIMIT %s", (n,))
    vecs = [np.array(r[0], dtype=np.float32).reshape(4, 128) for r in cur.fetchall()]
    conn.close()
    return vecs


def load_step2_vectors(n):
    conn = psycopg2.connect(**DB_CONFIG)
    cur = conn.cursor()
    cur.execute("SELECT get_mvec_data(text_vec) FROM reasoning_vector_step2 ORDER BY id LIMIT %s", (2 * n,))
    vecs = [np.array(r[0], dtype=np.float32).reshape(4, 128) for r in cur.fetchall()]
    conn.close()
    return vecs


def simulate_dbagent_pipeline(n):
    """
    Simulate what dbagent actually does based on code analysis:
    1. cross_encoder on all N vectors
    2. For each sample: deberta_reader -> evaluation (CallToolReaderDecoder)
    """
    full_start = time.perf_counter()
    
    # Load models
    model_cross = torch.jit.load(f"{MODEL_DIR}/cross_encoder.pt", map_location="cpu")
    model_cross.eval()
    model_reader = torch.jit.load(f"{MODEL_DIR}/deberta_reader.pt", map_location="cpu")
    model_reader.eval()
    
    # Load data
    input_vecs = load_mvec_vectors(n)
    step2_vecs = load_step2_vectors(n)
    
    # Stage 1: cross_encoder
    t0 = time.perf_counter()
    batch = torch.from_numpy(np.stack([v[:2, :] for v in input_vecs], axis=0).astype(np.float32))
    with torch.no_grad():
        scores = model_cross(batch).squeeze(-1).tolist()
    cross_time = time.perf_counter() - t0
    
    # Stage 2: For each sample - deberta_reader + reader_decoder
    t0 = time.perf_counter()
    all_outputs = []
    for i in range(n):
        idx = i * 2
        # deberta_reader
        reader_inputs = np.stack([step2_vecs[idx][:2, :], step2_vecs[idx+1][:2, :]], axis=0).astype(np.float32)
        reader_batch = torch.from_numpy(reader_inputs)
        with torch.no_grad():
            reader_output = model_reader(reader_batch)
        start_logits, end_logits = reader_output[:, 0, :], reader_output[:, 1, :]
        
        # Simulate evaluation agent: build res_str for reader_decoder
        res_str_parts = []
        for j in [0, 1]:
            vec_idx = idx + j
            input_ids = step2_vecs[vec_idx][0, :].astype(int).tolist()
            s = int(start_logits[j].argmax().item())
            e = int(end_logits[j].argmax().item())
            res_str_parts.append(",".join(str(t) for t in input_ids[s:e+1]))
        res_str = ";".join(res_str_parts)
        
        # Call reader_decoder.py (this is what dbagent does in EvaluationAgent)
        result = sp.run(
            ["uv", "run", f"{TOOLS_DIR}/reader_decoder.py", "--ids", res_str],
            capture_output=True, text=True, cwd=TOOLS_DIR, timeout=60
        )
        all_outputs.append(result.stdout.strip())
    
    reader_and_decoder_time = time.perf_counter() - t0
    total_time = time.perf_counter() - full_start
    
    return {
        "cross_encoder": cross_time,
        "deberta_reader+decoder": reader_and_decoder_time,
        "total": total_time,
        "outputs": all_outputs[:2],  # Just show first 2 outputs
    }


def simulate_pure_python_pipeline(n):
    """Pure Python pipeline without reader_decoder."""
    full_start = time.perf_counter()
    
    # Load models
    model_cross = torch.jit.load(f"{MODEL_DIR}/cross_encoder.pt", map_location="cpu")
    model_cross.eval()
    model_reader = torch.jit.load(f"{MODEL_DIR}/deberta_reader.pt", map_location="cpu")
    model_reader.eval()
    
    # Load data
    input_vecs = load_mvec_vectors(n)
    step2_vecs = load_step2_vectors(n)
    
    # Stage 1: cross_encoder
    t0 = time.perf_counter()
    batch = torch.from_numpy(np.stack([v[:2, :] for v in input_vecs], axis=0).astype(np.float32))
    with torch.no_grad():
        scores = model_cross(batch).squeeze(-1).tolist()
    cross_time = time.perf_counter() - t0
    
    # Stage 2: deberta_reader only (no reader_decoder)
    t0 = time.perf_counter()
    all_outputs = []
    for i in range(n):
        idx = i * 2
        reader_inputs = np.stack([step2_vecs[idx][:2, :], step2_vecs[idx+1][:2, :]], axis=0).astype(np.float32)
        reader_batch = torch.from_numpy(reader_inputs)
        with torch.no_grad():
            reader_output = model_reader(reader_batch)
        all_outputs.append(reader_output.tolist())
    reader_time = time.perf_counter() - t0
    
    total_time = time.perf_counter() - full_start
    
    return {
        "cross_encoder": cross_time,
        "deberta_reader": reader_time,
        "total": total_time,
    }


def main():
    print("=" * 70)
    print("  Verifying dbagent Pipeline: Does it call reader_decoder?")
    print("=" * 70)
    
    for n in [1, 5]:
        print(f"\n{'='*70}")
        print(f"  N={n}")
        print(f"{'='*70}")
        
        # Pure Python (no reader_decoder)
        print(f"\n[Pure Python] cross_encoder + deberta_reader only:")
        pure = simulate_pure_python_pipeline(n)
        print(f"  cross_encoder: {pure['cross_encoder']:.4f}s")
        print(f"  deberta_reader: {pure['deberta_reader']:.4f}s")
        print(f"  TOTAL: {pure['total']:.4f}s")
        
        # dbagent simulation (with reader_decoder)
        print(f"\n[dbagent Simulation] cross_encoder + deberta_reader + reader_decoder:")
        sim = simulate_dbagent_pipeline(n)
        print(f"  cross_encoder: {sim['cross_encoder']:.4f}s")
        print(f"  deberta_reader+decoder: {sim['deberta_reader+decoder']:.4f}s")
        print(f"  TOTAL: {sim['total']:.4f}s")
        print(f"  reader_decoder outputs (first 2):")
        for i, out in enumerate(sim['outputs'][:2]):
            print(f"    Sample {i}: {out[:100]}...")
        
        print(f"\n  Difference: {sim['total'] - pure['total']:.4f}s (due to reader_decoder)")
        print(f"  reader_decoder overhead: {sim['deberta_reader+decoder'] - pure['deberta_reader']:.4f}s")
    
    print(f"\n{'='*70}")
    print("  CONCLUSION")
    print(f"{'='*70}")
    print("  dbagent DOES call reader_decoder.py in EvaluationAgent for STEP2 tasks!")
    print("  This explains the additional ~17s overhead:")
    print("    - ~1.2s: Model loading")
    print("    - ~1.7s: Data loading")
    print("    - ~0.6s: Pure inference (cross_encoder + deberta)")
    print("    - ~15s: reader_decoder.py subprocess calls (per sample)")
    print("    - ~2s: PostgreSQL/pgdl overhead")
    print("=" * 70)


if __name__ == "__main__":
    main()
