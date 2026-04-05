#!/usr/bin/env python3
"""Test Python mel → encoder → decoder with proper autoregressive decoding."""

import numpy as np
import soundfile as sf
import coremltools as ct
from transformers import AutoProcessor
from cohere_mel_spectrogram import CohereMelSpectrogram

print("Testing PYTHON MEL with AUTOREGRESSIVE DECODING")
print("="*70)

# Load tokenizer
processor = AutoProcessor.from_pretrained(
    "CohereLabs/cohere-transcribe-03-2026",
    trust_remote_code=True
)
tokenizer = processor.tokenizer

# Load audio
audio, sr = sf.read("test-librispeech-real.wav")
if sr != 16000:
    raise ValueError(f"Audio must be 16kHz, got {sr}Hz")

duration = len(audio) / 16000
print(f"Audio: test-librispeech-real.wav ({duration:.2f}s, {len(audio)} samples)")

# Python Mel Spectrogram
print("\n[1/3] Python Mel Spectrogram...")
mel_processor = CohereMelSpectrogram()
mel = mel_processor(audio)
print(f"   Mel shape (before padding): {mel.shape}")
print(f"   Mel stats: mean={mel.mean():.6f}, std={mel.std():.6f}")

# Pad to 3501 frames
mel_padded = np.pad(
    mel,
    ((0, 0), (0, 0), (0, 3501 - mel.shape[2])),
    mode='constant',
    constant_values=0
)
print(f"   Mel shape (after padding): {mel_padded.shape}")

# Encoder
print("\n[2/3] Encoder...")
encoder = ct.models.MLModel(
    "build/barathwaj-models/cohere_encoder.mlpackage",
    compute_units=ct.ComputeUnit.CPU_AND_GPU
)
encoder_output = encoder.predict({
    "input_features": mel_padded.astype(np.float32),
    "feature_length": np.array([3501], dtype=np.int32)
})

# Find encoder output
hidden_states = None
for key, value in encoder_output.items():
    if hasattr(value, 'shape') and len(value.shape) == 3 and value.shape[1] == 438:
        hidden_states = value
        print(f"   Hidden states: {value.shape}")
        break

if hidden_states is None:
    raise ValueError("Could not find encoder output")

# Decoder - AUTOREGRESSIVE with cached decoder
print("\n[3/3] Autoregressive Decoding...")
decoder = ct.models.MLModel(
    "build/barathwaj-models/cohere_decoder_cached.mlpackage",
    compute_units=ct.ComputeUnit.CPU_AND_GPU
)

# Check decoder inputs
spec = decoder.get_spec()
print(f"   Decoder inputs:")
for inp in spec.description.input:
    print(f"     - {inp.name}")

# Start with decoder_start_token_id
decoder_start_token_id = 13764  # from generation_config.json
eos_token_id = 3
max_new_tokens = 100

generated_tokens = [decoder_start_token_id]
past_key_values = None

print(f"   Starting autoregressive generation (max {max_new_tokens} tokens)...")

for step in range(max_new_tokens):
    # Prepare input
    decoder_input = {
        "input_id": np.array([[generated_tokens[-1]]], dtype=np.int32),  # shape [1, 1]
        "encoder_hidden_states": hidden_states.astype(np.float16),
        "step": np.array([step], dtype=np.int32),  # shape [1]
        "cross_attention_mask": np.ones((1, 1, 1, 438), dtype=np.float16),
    }

    # Initialize cache on first step
    if step == 0:
        # Cache shape: [8 layers, 8 heads, 108 max_seq_len, 128 dim_per_head]
        decoder_input["cache_k"] = np.zeros((8, 8, 108, 128), dtype=np.float16)
        decoder_input["cache_v"] = np.zeros((8, 8, 108, 128), dtype=np.float16)
    else:
        # Use previous cache (outputs are var_2894 and var_2897)
        decoder_input["cache_k"] = past_key_values["var_2894"]
        decoder_input["cache_v"] = past_key_values["var_2897"]

    try:
        decoder_output = decoder.predict(decoder_input)
    except Exception as e:
        print(f"   ❌ Decoder error at step {step}: {e}")
        break

    # Extract logits and new cache (outputs: var_2891=logits, var_2894=cache_k, var_2897=cache_v)
    logits = decoder_output.get("var_2891")
    if logits is None:
        print(f"   ❌ Could not find logits (var_2891) in output: {list(decoder_output.keys())}")
        break

    new_cache = {
        "var_2894": decoder_output["var_2894"],  # new cache_k
        "var_2897": decoder_output["var_2897"],  # new cache_v
    }

    # Get next token (logits shape is [1, 16384])
    next_token = int(np.argmax(logits[0]))

    generated_tokens.append(next_token)
    past_key_values = new_cache

    # Stop at EOS
    if next_token == eos_token_id:
        print(f"   ✓ Generated {len(generated_tokens)-1} tokens (stopped at EOS)")
        break

    if (step + 1) % 20 == 0:
        print(f"   ... {step+1} tokens generated")

if generated_tokens[-1] != eos_token_id:
    print(f"   ⚠ Reached max_new_tokens without EOS")

# Decode (skip the start token)
transcription = tokenizer.decode(generated_tokens[1:], skip_special_tokens=True)

print("\n" + "="*70)
print("PYTHON MEL TRANSCRIPTION")
print("="*70)
print(f'"{transcription}"')
print("="*70)
print(f"\nGenerated {len(generated_tokens)-1} tokens")
print(f"Token IDs (first 20): {generated_tokens[:20]}")

# Compare with expected
expected = "he hoped there would be stew for dinner turnips and carrots and bruised potatoes and fat mutton pieces to be ladled out in thick peppered flour fattened sauce"

print("\n" + "="*70)
if transcription.lower().strip() == expected.lower().strip():
    print("✅ SUCCESS: Python mel works perfectly!")
elif "it's not a big deal" in transcription.lower():
    print("❌ FAILED: Python mel produces garbage")
elif transcription.lower().strip().startswith("he hoped there would be stew"):
    print("⚠️  PARTIAL: Starts correctly but diverges")
    print(f"   This suggests the Python mel is close but not exact")
else:
    print("❌ FAILED: Completely wrong output")
print("="*70)
