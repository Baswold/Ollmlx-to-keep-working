# ollmlx 🚀

**Apple Silicon Optimized LLM Inference** | **100% Ollama Compatible** | **MLX-Powered (GGUF replaced)**

> **⚡ Claude Merged Edition** - This version combines the excellent infrastructure from `small_model` with the fully functional MLX backend from `big_model`. See [MERGE_SUMMARY.md](MERGE_SUMMARY.md) for details.

![ollmlx logo](https://github.com/ollama/ollama/assets/3325447/0d0b44e2-8f4a-4e99-9b52-a5c1c741c8f7)

> **ollmlx** is a high-performance LLM inference server optimized for Apple Silicon, delivering blazing-fast inference with full Ollama API compatibility.

## 🎯 What is ollmlx?

ollmlx is a **drop-in replacement** for Ollama that swaps the GGUF/llama.cpp backend for Apple's **MLX** stack, while keeping the same CLI and HTTP API:

- **⚡ Faster inference on Apple Silicon** (M1/M2/M3) by running MLX-native weights
- **🔄 Exact Ollama API/CLI compatibility** – same commands/endpoints/ports
- **📦 MLX model support** – pull HF `mlx-community/*` or `*-mlx` models directly
- **🧠 Unified memory efficiency** – takes advantage of MLX on macOS
- **💡 Simple swap** – keep your tools/IDE integrations; just point them at ollmlx

## 🚀 Quick Start

> 📖 **New here?** Check out [QUICKSTART.md](QUICKSTART.md) for a beginner-friendly guide!

### 1. Install

```bash
# Clone the repository
git clone https://github.com/ollama/ollama.git
cd ollama

# Build ollmlx (uses OLLAMA_MODELS for both GGUF and MLX caches; MLX stored under $(OLLAMA_MODELS)/mlx)
go build -o ollmlx .

# Install Python dependencies
pip install -r mlx_backend/requirements.txt

# Start the server
./ollmlx serve

# Optional: relocate caches
# export OLLAMA_MODELS=~/ollmlx-models
```

### 2. Pull a Model

```bash
# Pull a small, fast model
ollmlx pull mlx-community/SmolLM2-135M-Instruct-4bit

# Or try a larger model
ollmlx pull mlx-community/Llama-3.2-1B-Instruct-4bit
```

### 3. Chat with the Model

```bash
# Interactive chat
ollmlx run mlx-community/Llama-3.2-1B-Instruct-4bit

# Or use the API
curl http://localhost:11434/api/generate -d '{
  "model": "mlx-community/Llama-3.2-1B-Instruct-4bit",
  "prompt": "Explain quantum computing in simple terms.",
  "stream": false
}'
```

## 📊 Performance Comparison

| Metric               | ollmlx (MLX) | Ollama (GGUF) | Improvement |
|----------------------|--------------|---------------|-------------|
| Token generation     | 2-3x faster  | Baseline      | 200-300%    |
| First token latency  | ~50ms        | ~150ms        | 70% faster  |
| Memory usage         | Lower        | Higher        | Better      |
| Apple Silicon usage  | Optimized    | Generic      | ✅          |

> **Note:** Performance varies by model size and hardware. MLX is specifically optimized for Apple Silicon's unified memory architecture.

## 🎯 Why ollmlx?

### For Developers
- **Faster iteration** - Get responses instantly
- **Better resource usage** - Run more models simultaneously
- **Future-proof** - Built on Apple's modern ML framework

### For AI Enthusiasts
- **Try the latest models** - MLX models are cutting-edge
- **Better experience** - Smoother, more responsive interactions
- **Community-driven** - Join the MLX ecosystem

### For Businesses
- **Cost-effective** - Lower cloud costs with local inference
- **Privacy-focused** - All processing happens locally
- **Reliable** - No internet required after setup

## 📚 Supported Models

ollmlx supports all MLX models from HuggingFace, including:

### 🏆 Top Picks

| Model                          | Size       | Parameters | Best For                     |
|-------------------------------|------------|------------|------------------------------|
| **Llama 3.2 1B**              | ~750MB     | 1B         | General chat, coding         |
| **Llama 3.2 3B**              | ~2GB       | 3B         | Advanced tasks               |
| **Mistral 7B**                | ~4GB       | 7B         | High-quality responses       |
| **Phi-3.5 Mini**              | ~2.3GB     | 3.8B       | Fast, accurate responses     |
| **Gemma 2 2B**                 | ~1.5GB     | 2B         | Multilingual support         |
| **Qwen 2.5 7B**                | ~4GB       | 7B         | Coding assistance            |

### 🐣 Small & Fast

| Model                          | Size       | Parameters |
|-------------------------------|------------|------------|
| SmolLM2 135M                  | ~150MB     | 135M       |
| SmolLM2 1.7B                  | ~1GB       | 1.7B       |

### 📈 All Available Models

Browse the full list: [https://huggingface.co/mlx-community](https://huggingface.co/mlx-community)

## 🛠️ Usage Examples

### Basic Chat

```bash
# Start a chat session
ollmlx run mlx-community/Llama-3.2-1B-Instruct-4bit

# Type your messages and get instant responses
```

### API Integration

```bash
# Generate text
curl http://localhost:11434/api/generate -d '{
  "model": "mlx-community/Llama-3.2-1B-Instruct-4bit",
  "prompt": "Write a Python function to sort a list.",
  "stream": false,
  "options": {
    "temperature": 0.7,
    "max_tokens": 100
  }
}'

# Stream responses
curl http://localhost:11434/api/generate -d '{
  "model": "mlx-community/Llama-3.2-1B-Instruct-4bit",
  "prompt": "Explain machine learning.",
  "stream": true
}'
```

### List Models

```bash
# See all installed models
ollmlx list

# Get detailed info about a model
ollmlx show mlx-community/Llama-3.2-1B-Instruct-4bit
```

### Delete Models

```bash
# Remove a model to free up space
ollmlx delete mlx-community/Llama-3.2-1B-Instruct-4bit
```

## 🔧 Advanced Usage

### Custom Models

You can use any MLX model from HuggingFace:

```bash
# Pull any mlx-community model
ollmlx pull mlx-community/YourModelName

# Or use a model directly from HuggingFace
ollmlx run mlx-community/YourModelName
```

### Configuration

Create a `config.json` file to customize behavior:

```json
{
  "models": {
    "default": "mlx-community/Llama-3.2-1B-Instruct-4bit"
  },
  "server": {
    "port": 11434,
    "host": "localhost"
  }
}
```

### Environment Variables

```bash
# Custom port
export OLMLX_PORT=11435

# Custom model directory
export OLMLX_MODELS_DIR=~/custom-models

# Verbose logging
export OLMLX_LOG_LEVEL=debug
```

## 📈 Monitoring & Metrics

ollmlx provides detailed metrics:

```bash
# Check server status
curl http://localhost:11434/api/version

# Get system info
curl http://localhost:11434/api/tags

# Monitor active requests
curl http://localhost:11434/api/ps
```

## 🤖 IDE & Tool Integration

ollmlx works seamlessly with:

- **VS Code** - Use with Ollama extensions
- **GitHub Copilot** - Local model fallback
- **JetBrains IDEs** - Ollama plugin support
- **LangChain** - Full compatibility
- **LlamaIndex** - Works out of the box
- **Any Ollama client** - 100% API compatible

## 🔄 Migration from Ollama

Switching from Ollama to ollmlx is easy:

1. **Install ollmlx** alongside Ollama
2. **Pull MLX models** using ollmlx
3. **Update your tools** to point to ollmlx
4. **Enjoy faster performance**!

> **Note:** ollmlx maintains the same API, so no code changes are needed!

## 📦 Model Management

### Pulling Models

```bash
# Pull a model
ollmlx pull mlx-community/Llama-3.2-1B-Instruct-4bit

# Pull with progress tracking
ollmlx pull mlx-community/Llama-3.2-1B-Instruct-4bit --progress
```

### Listing Models

```bash
# List all models
ollmlx list

# List with details
ollmlx list --verbose
```

### Showing Model Info

```bash
# Get detailed model information
ollmlx show mlx-community/Llama-3.2-1B-Instruct-4bit

# Show size and format
ollmlx show --format json mlx-community/Llama-3.2-1B-Instruct-4bit
```

### Deleting Models

```bash
# Remove a model
ollmlx delete mlx-community/Llama-3.2-1B-Instruct-4bit

# Force delete (skip confirmation)
ollmlx delete --force mlx-community/Llama-3.2-1B-Instruct-4bit
```

## 🛡️ Security

ollmlx includes several security features:

- **Local-only by default** - Only listens on localhost
- **No telemetry** - No data leaves your machine
- **Model verification** - Checks model integrity
- **Safe defaults** - Conservative resource limits

## 🐛 Troubleshooting

### Common Issues

#### MLX backend won't start

```bash
# Check Python dependencies
pip install -r mlx_backend/requirements.txt

# Verify Python version
python3 --version  # Should be 3.10+
```

#### Model download fails

```bash
# Check internet connection
ping huggingface.co

# Try again with verbose output
ollmlx pull mlx-community/ModelName --verbose
```

#### Out of memory

```bash
# Use a smaller model
ollmlx pull mlx-community/SmolLM2-135M-Instruct-4bit

# Close other applications
# Check available memory
```

#### Slow performance

```bash
# Try a different model
ollmlx pull mlx-community/Phi-3.5-mini-instruct-4bit

# Check system resources
top -o cpu -R
```

### Getting Help

- **GitHub Issues**: [https://github.com/ollama/ollama/issues](https://github.com/ollama/ollama/issues)
- **Discord**: Join our community
- **Email**: Support email if available

## 📖 Documentation

- **[Architecture](docs/MLX_ARCHITECTURE.md)** - Technical details
- **[Supported Models](docs/SUPPORTED_MODELS.md)** - Full model list
- **[Migration Guide](docs/MIGRATION_FROM_OLLAMA.md)** - Switching from Ollama
- **[API Reference](api/)** - Complete API documentation

## 🤝 Contributing

We welcome contributions! Here's how you can help:

1. **Report bugs** - Open issues for any problems
2. **Suggest features** - Propose new ideas
3. **Improve documentation** - Fix typos, add examples
4. **Add models** - Contribute new MLX model configurations
5. **Optimize performance** - Help improve MLX integration

### Development Setup

```bash
# Clone the repository
git clone https://github.com/ollama/ollama.git
cd ollama

# Install dependencies
go mod download
pip install -r mlx_backend/requirements.txt

# Build and test
make test
```

## 📄 License

This project is licensed under the **MIT License** - see the [LICENSE](LICENSE) file for details.

## 🌟 Acknowledgements

- **Apple MLX Team** - For creating the amazing MLX framework
- **HuggingFace** - For hosting MLX models
- **Ollama Community** - For inspiration and API compatibility
- **All Contributors** - For making this project better

## 📞 Contact

For questions or feedback, please open an issue on GitHub.

---

**ollmlx** - Making LLM inference fast, efficient, and accessible on Apple Silicon.

![Apple Silicon](https://developer.apple.com/assets/elements/badges/download-on-the-mac-app-store.svg)
