# Supported MLX Models

This document lists MLX models that have been tested with ollmlx, along with performance benchmarks and usage notes.

## Quick Reference

All models listed below are available from HuggingFace's `mlx-community` organization.

**Install Command Format**:
```bash
ollama pull mlx-community/<model-name>
```

## Tested Models

### Llama Models

| Model | Size | Quantization | Performance (M2) | Memory | Status |
|-------|------|--------------|------------------|---------|--------|
| Llama-3.2-1B-Instruct-4bit | 1B | 4-bit | 45 tokens/sec | ~1.2GB | Excellent |
| Llama-3.2-3B-Instruct-4bit | 3B | 4-bit | 28 tokens/sec | ~2.8GB | Excellent |
| Llama-3.1-8B-Instruct-4bit | 8B | 4-bit | 12 tokens/sec | ~5.5GB | Good |
| Llama-3-8B-Instruct-4bit | 8B | 4-bit | 11 tokens/sec | ~5.3GB | Good |

**Usage**:
```bash
ollama pull mlx-community/Llama-3.2-1B-Instruct-4bit
ollama run mlx-community/Llama-3.2-1B-Instruct-4bit
```

**Notes**:
- Llama 3.2 models are optimized for instruction following
- 1B and 3B models are excellent for local development
- 8B models require 16GB RAM for comfortable use

### Mistral Models

| Model | Size | Quantization | Performance (M2) | Memory | Status |
|-------|------|--------------|------------------|---------|--------|
| Mistral-7B-Instruct-v0.3-4bit | 7B | 4-bit | 13 tokens/sec | ~4.8GB | Excellent |
| Mistral-7B-Instruct-v0.2-4bit | 7B | 4-bit | 13 tokens/sec | ~4.8GB | Good |
| Mixtral-8x7B-Instruct-v0.1-4bit | 8x7B | 4-bit | 4 tokens/sec | ~26GB | Requires 32GB RAM |

**Usage**:
```bash
ollama pull mlx-community/Mistral-7B-Instruct-v0.3-4bit
```

**Notes**:
- Mistral models excel at coding tasks
- v0.3 has improved instruction following over v0.2
- Mixtral is a Mixture-of-Experts model (very powerful but large)

### Qwen Models

| Model | Size | Quantization | Performance (M2) | Memory | Status |
|-------|------|--------------|------------------|---------|--------|
| Qwen2.5-0.5B-Instruct-4bit | 0.5B | 4-bit | 65 tokens/sec | ~600MB | Excellent |
| Qwen2.5-1.5B-Instruct-4bit | 1.5B | 4-bit | 40 tokens/sec | ~1.5GB | Excellent |
| Qwen2.5-3B-Instruct-4bit | 3B | 4-bit | 25 tokens/sec | ~2.6GB | Excellent |
| Qwen2.5-7B-Instruct-4bit | 7B | 4-bit | 12 tokens/sec | ~5.2GB | Good |

**Usage**:
```bash
ollama pull mlx-community/Qwen2.5-7B-Instruct-4bit
```

**Notes**:
- Qwen models are multilingual (English, Chinese, and more)
- 0.5B and 1.5B models are incredibly fast on Apple Silicon
- Strong performance on reasoning tasks

### Phi Models

| Model | Size | Quantization | Performance (M2) | Memory | Status |
|-------|------|--------------|------------------|---------|--------|
| Phi-3.5-mini-instruct-4bit | 3.8B | 4-bit | 22 tokens/sec | ~2.8GB | Excellent |
| Phi-3-mini-4k-instruct-4bit | 3.8B | 4-bit | 22 tokens/sec | ~2.8GB | Good |
| Phi-4-4bit | 14B | 4-bit | 7 tokens/sec | ~9.5GB | Good |

**Usage**:
```bash
ollama pull mlx-community/Phi-3.5-mini-instruct-4bit
```

**Notes**:
- Phi models are optimized for coding and reasoning
- "Mini" models punch above their weight class
- Phi-4 requires more memory but delivers excellent quality

### Gemma Models

| Model | Size | Quantization | Performance (M2) | Memory | Status |
|-------|------|--------------|------------------|---------|--------|
| gemma-2-2b-it-4bit | 2B | 4-bit | 35 tokens/sec | ~1.8GB | Excellent |
| gemma-2-9b-it-4bit | 9B | 4-bit | 10 tokens/sec | ~6.2GB | Good |
| gemma-2-27b-it-4bit | 27B | 4-bit | 3 tokens/sec | ~18GB | Requires 24GB RAM |

**Usage**:
```bash
ollama pull mlx-community/gemma-2-2b-it-4bit
```

**Notes**:
- Gemma models are Google's open LLMs
- "it" suffix means "instruction tuned"
- 2B model is very fast and capable

### SmolLM Models

| Model | Size | Quantization | Performance (M2) | Memory | Status |
|-------|------|--------------|------------------|---------|--------|
| SmolLM2-135M-Instruct-4bit | 135M | 4-bit | 120 tokens/sec | ~250MB | Excellent |
| SmolLM2-360M-Instruct-4bit | 360M | 4-bit | 85 tokens/sec | ~450MB | Excellent |
| SmolLM2-1.7B-Instruct-4bit | 1.7B | 4-bit | 40 tokens/sec | ~1.5GB | Excellent |

**Usage**:
```bash
ollama pull mlx-community/SmolLM2-135M-Instruct-4bit
```

**Notes**:
- SmolLM models are incredibly tiny and fast
- Perfect for testing, prototyping, and resource-constrained environments
- 135M model is the smallest practical instruction-following model

## Performance Benchmarks

### Test Environment
- **Hardware**: M2 MacBook Air, 16GB RAM
- **OS**: macOS 14.0
- **MLX Version**: 0.19.0
- **Prompt**: "Explain quantum computing in simple terms."
- **Length**: 100 tokens

### MLX vs GGUF Comparison

| Model | MLX (tokens/sec) | GGUF (tokens/sec) | Speedup | Memory (MLX) | Memory (GGUF) |
|-------|------------------|-------------------|---------|--------------|---------------|
| Llama 3.2 1B | 45 | 32 | **+40%** | 1.2GB | 1.4GB |
| Llama 3.2 3B | 28 | 20 | **+40%** | 2.8GB | 3.1GB |
| Mistral 7B | 13 | 9 | **+44%** | 4.8GB | 5.3GB |
| Qwen 2.5 7B | 12 | 8.5 | **+41%** | 5.2GB | 5.7GB |

### Hardware Scaling

| Model | M1 (8GB) | M2 (16GB) | M3 Pro (32GB) |
|-------|----------|-----------|---------------|
| Llama 3.2 1B | 38 tok/s | 45 tok/s | 52 tok/s |
| Llama 3.2 3B | 23 tok/s | 28 tok/s | 34 tok/s |
| Mistral 7B | 10 tok/s | 13 tok/s | 16 tok/s |

*Note: Performance varies based on model, prompt length, and system load*

## Quantization Levels

MLX supports multiple quantization levels. Most community models use 4-bit:

| Quantization | Quality | Speed | Memory | Use Case |
|--------------|---------|-------|--------|----------|
| 4-bit | Good | Fast | Low | Recommended for most users |
| 8-bit | Better | Medium | Medium | High-quality responses needed |
| 16-bit (fp16) | Best | Slow | High | Maximum quality, research |

**Finding Other Quantizations**:
Browse HuggingFace: https://huggingface.co/mlx-community

## Model Selection Guide

### For Development/Testing
- **SmolLM2-135M-Instruct-4bit** - Extremely fast, good for prototyping
- **Qwen2.5-0.5B-Instruct-4bit** - Fastest viable instruction model

### For General Chat
- **Llama-3.2-3B-Instruct-4bit** - Best balance of speed and quality
- **Qwen2.5-3B-Instruct-4bit** - Strong multilingual support

### For Coding
- **Phi-3.5-mini-instruct-4bit** - Optimized for code
- **Mistral-7B-Instruct-v0.3-4bit** - Excellent code generation

### For Complex Reasoning
- **Llama-3.1-8B-Instruct-4bit** - Strong reasoning capabilities
- **Qwen2.5-7B-Instruct-4bit** - Multi-step problem solving

### For Maximum Quality (if you have RAM)
- **Phi-4-4bit** (14B) - Latest reasoning model
- **Mistral-7B-Instruct-v0.3-4bit** - Proven performance
- **Mixtral-8x7B-Instruct-v0.1-4bit** (requires 32GB RAM) - Best overall

## Known Issues

### Model-Specific Issues

**Mixtral-8x7B**:
- Requires 32GB RAM minimum
- May have stability issues on 16GB systems
- Use with `num_parallel=1` for better stability

**Older Llama 3 Models**:
- Some early 3.0 models may have formatting quirks
- Prefer 3.1 or 3.2 versions when available

### General Issues

**First-Token Latency**:
- MLX models have ~100-500ms warm-up on first generation
- Subsequent generations are fast
- This is normal MLX behavior (model loading + compilation)

**Memory Spikes**:
- Initial model load may briefly spike memory
- Monitor Activity Monitor when testing large models
- Close other apps if using 8GB or 16GB systems

## Finding More Models

### HuggingFace Search
```bash
# List all MLX community models
curl https://huggingface.co/api/models?search=mlx-community
```

### Recommended Sources
1. **mlx-community** - Official MLX model conversions
2. **mlx-compatible tags** - Community conversions
3. **Ollama library** - Cross-reference with GGUF versions

### Converting Your Own Models
If you have a HuggingFace model you want to convert to MLX:

```bash
# Install MLX conversion tools
pip install mlx-lm

# Convert a model
python -m mlx_lm.convert \
    --hf-path <huggingface-model-name> \
    --mlx-path ./my-mlx-model \
    --quantize
```

See [MLX documentation](https://github.com/ml-explore/mlx-examples/tree/main/llms) for details.

## Reporting Issues

If you encounter problems with a specific model:

1. Check model exists: `curl https://huggingface.co/mlx-community/<model-name>`
2. Verify local cache: `ls ~/.ollama/models/mlx/`
3. Test MLX backend directly: `cd mlx_backend && python server.py`
4. Report issue with:
   - Model name and version
   - Hardware (M1/M2/M3, RAM)
   - Error message
   - `ollama --version`

## Performance Tips

### Maximizing Speed
1. **Close other apps** - Free up RAM for model
2. **Use 4-bit models** - Best speed/quality trade-off
3. **Adjust temperature** - Lower values (0.1-0.5) are faster
4. **Limit output length** - Use `num_predict` parameter

### Saving Memory
1. **Unload models** - `ollama rm <model>` when not needed
2. **Use smaller models** - 1B-3B for most tasks
3. **Monitor usage** - Activity Monitor → Memory tab
4. **One model at a time** - Don't run multiple models simultaneously

## Contributing

Help expand this list!

- Test models on different hardware (M1/M2/M3/M4)
- Submit benchmarks for untested models
- Report issues or success stories
- Suggest models for testing priority

Submit updates via pull request or issue on GitHub.

---

**Last Updated**: 2025-12-10
**Test Environment**: M2 MacBook Air (16GB), macOS 14.0, MLX 0.19.0
