#!/usr/bin/env python3
"""per_layer_replay.py — Feed fixture inputs to bpd_llama_block_cpu per-layer.

For each transformer layer:
  1. Take the FIXTURE input (l_out from previous layer, or inp_embd for layer 0)
  2. Run bpd_llama_block_cpu on that input with FIXTURE weights
  3. Compare our output against the FIXTURE output (l_out-N)
  4. First diverging layer = the wiring bug

This tests the ORCHESTRATOR, not individual kernels.
"""

import sys, os, numpy as np, ctypes, argparse
sys.path.insert(0, "bench")
sys.path.insert(0, "tests/correctness")
from llama_fixture_loader import load_manifest, get_sources

c_float_p = ctypes.POINTER(ctypes.c_float)
c_uint8_p = ctypes.POINTER(ctypes.c_uint8)


def main():
    p = argparse.ArgumentParser()
    p.add_argument("--fixture-dir", required=True)
    p.add_argument("--so", required=True)
    p.add_argument("--gguf", required=True)
    p.add_argument("--max-layers", type=int, default=16)
    args = p.parse_args()

    tensors = load_manifest(args.fixture_dir)
    by_idx = {t.idx: t for t in tensors}
    
    lib = ctypes.CDLL(args.so)
    
    print("[replay] Per-layer orchestrator wiring test")
    print("[replay] %d fixture tensors loaded" % len(tensors))
    print()

    # Find layer boundary tensors (second occurrence = actual computation)
    # Pattern: l_out-N appears twice, second is the real one
    layer_outputs = {}  # layer_num → (idx, tensor)
    layer_inputs = {}   # layer_num → (idx, tensor) -- ffn_inp or l_out of prev layer
    
    for t in tensors:
        name = t.name
        if name.startswith("l_out-"):
            layer_num = int(name.split("-")[1])
            # Keep the SECOND occurrence (higher idx = actual computation)
            if layer_num not in layer_outputs or t.idx > layer_outputs[layer_num][0]:
                layer_outputs[layer_num] = (t.idx, t)
        
        if name.startswith("ffn_inp-"):
            layer_num = int(name.split("-")[1])
            if layer_num not in layer_inputs or t.idx > layer_inputs[layer_num][0]:
                layer_inputs[layer_num] = (t.idx, t)

    # Also find inp_embd (second occurrence)
    embd_tensors = [(t.idx, t) for t in tensors if t.name == "inp_embd"]
    if len(embd_tensors) >= 2:
        inp_embd = embd_tensors[1][1]  # second occurrence
    else:
        inp_embd = embd_tensors[0][1]

    print("Layer boundary tensors found:")
    print("  inp_embd: idx=%d shape=%s" % (inp_embd.idx, list(inp_embd.ne)))
    for L in sorted(layer_outputs.keys()):
        idx, t = layer_outputs[L]
        print("  l_out-%d: idx=%d shape=%s" % (L, idx, list(t.ne)))
    
    print()

    # For each layer: compare fixture input → fixture output
    # to verify the CHAIN is consistent
    print("=== Layer-by-layer fixture chain verification ===")
    print("(Checking that each layer's output feeds correctly to the next)")
    print()

    prev_output = np.ascontiguousarray(inp_embd.as_numpy(), dtype=np.float32).flatten()
    
    for L in range(min(args.max_layers, len(layer_outputs))):
        if L not in layer_outputs:
            continue
        
        _, l_out_tensor = layer_outputs[L]
        l_out_fixture = np.ascontiguousarray(l_out_tensor.as_numpy(), dtype=np.float32).flatten()
        
        # The input to this layer should be l_out of previous layer (or inp_embd)
        if L == 0:
            expected_input_idx = inp_embd.idx
        else:
            if L-1 in layer_outputs:
                expected_input_idx = layer_outputs[L-1][0]
            else:
                print("  Layer %d: missing previous layer output" % L)
                continue
        
        # Check if the source links of l_out-L eventually trace back to l_out-(L-1)
        # The l_out-L has src=(ffn_down_result, ffn_inp-L)
        # and ffn_inp-L has src=(attn_output, l_out-(L-1))
        
        sources = get_sources(tensors, l_out_tensor)
        src_names = [(s.idx, s.name) for s in sources]
        
        print("  Layer %d: l_out idx=%d, sources=%s" % (L, l_out_tensor.idx, src_names))
        
        # Check data magnitude and statistics
        print("           output range: [%.4f, %.4f] mean=%.4f" % (
            l_out_fixture.min(), l_out_fixture.max(), l_out_fixture.mean()))
        
        # Compare against what bpd_llama_forward_cpu would produce
        # For now, just verify the chain is consistent
        prev_output = l_out_fixture.copy()

    # Now the real test: find result_output and compare
    print()
    print("=== Final output comparison ===")
    result_tensors = [(t.idx, t) for t in tensors if t.name == "result_output"]
    if result_tensors:
        _, result = result_tensors[-1]
        result_data = np.ascontiguousarray(result.as_numpy(), dtype=np.float32).flatten()
        print("  result_output idx=%d: %d values, argmax=%d" % (
            result.idx, len(result_data), np.argmax(result_data)))
        print("  top-5 tokens: %s" % np.argsort(result_data)[-5:][::-1])
        print("  top-5 logits: %s" % result_data[np.argsort(result_data)[-5:][::-1]])
    
    # Now run our forward pass on the SAME input and compare
    print()
    print("=== Running bpd_llama_forward_cpu on fixture input ===")
    
    # Check if bpd_llama_forward_cpu exists
    if not hasattr(lib, 'bpd_llama_forward_cpu'):
        print("  bpd_llama_forward_cpu not found in %s" % args.so)
        print("  Cannot test orchestrator wiring.")
        return
    
    print("  bpd_llama_forward_cpu found — running end-to-end")
    # The end-to-end gate already tests this. What we need is
    # per-LAYER output comparison. That requires calling
    # bpd_llama_block_cpu for each layer individually.
    
    if not hasattr(lib, 'bpd_llama_block_cpu'):
        print("  bpd_llama_block_cpu not found — cannot do per-layer comparison")
        print("  The orchestrator is a monolithic forward pass.")
        print("  To find the wiring bug, we need to instrument bpd_llama_forward_cpu")
        print("  to dump intermediate tensors and compare against fixtures.")
        return
    
    print("  bpd_llama_block_cpu found — per-layer comparison possible")


if __name__ == "__main__":
    main()
