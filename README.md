# caniollama

[![PyPI version](https://badge.fury.io/py/caniollama.svg)](https://pypi.org/project/caniollama/)
[![License: MIT](https://img.shields.io/badge/License-MIT-yellow.svg)](https://opensource.org/licenses/MIT)
[![CI](https://github.com/AnjalLLL/caniollama/actions/workflows/ci.yml/badge.svg)](https://github.com/AnjalLLL/caniollama/actions/workflows/ci.yml)
[![CodeQL](https://github.com/AnjalLLL/caniollama/actions/workflows/codeql.yml/badge.svg)](https://github.com/AnjalLLL/caniollama/actions/workflows/codeql.yml)
[![Docs](https://img.shields.io/badge/docs-anjalll.github.io-blue)](https://anjalll.github.io/caniollama/)
[![Python 3.10+](https://img.shields.io/badge/python-3.10+-blue.svg)](https://www.python.org/downloads/)

**Standardized compatibility checker for local Ollama model tool-calling support.**

Does your local LLM actually support function calling? Run `caniollama check` to find out.

📖 **Docs:** https://anjalll.github.io/caniollama/ · 🌐 Landing page source: [`landing/`](landing/)

## What is this?

A CLI tool that tests whether Ollama models properly support tool/function calling. It runs a standardized test suite and categorizes models into:

1. ✅ **Native support** - Uses proper `tool_calls` field
2. 🟡 **Fallback mode** - Generates tool JSON in content
3. ❌ **Rejected** - Backend refuses tools parameter
4. ⚠️ **Error** - Timeouts or other failures

Results can be optionally submitted to a public registry for community benefit.

## Installation

### Quick Start (No Installation)

```bash
# Using uvx (recommended)
uvx caniollama check

# Or with pipx
pipx run caniollama check
```

### Permanent Installation

```bash
# Using pip
pip install caniollama

# Using pipx (isolated environment)
pipx install caniollama

# Using uv
uv tool install caniollama
```

See [Installation Guide](docs/installation.md) for detailed instructions, Docker setup, and troubleshooting.

### Check a specific model

```bash
caniollama check qwen2.5-coder:7b
```

### Submit results to public registry

```bash
caniollama check --submit
```

**Privacy:** Only metadata is submitted (model name, Ollama version, pass/fail outcomes). Never prompts or model outputs. See [docs/privacy.md](docs/privacy.md).

## Why?

Not all models that claim tool-calling support actually work with your local Ollama setup. This tool:

- **Tests real behavior** - Not based on model cards or documentation
- **Standardized suite** - Same tests across all models for fair comparison  
- **Community data** - Public registry helps everyone make informed choices
- **Integration-ready** - API for tools to query compatibility

## Repository Structure

This monorepo contains:

- **`compat-check/`** - CLI tool (published to PyPI as `caniollama`)
- **`compat-registry/`** - Public registry backend (FastAPI service)
- **`docs/`** - Documentation and guides
- **`tests/`** - Cross-package integration tests

## Documentation

### User Guides
- 📦 [Installation Guide](docs/installation.md) - Detailed installation for CLI and registry
- 📖 [CLI Usage Guide](compat-check/README.md) - Command-line tool documentation
- 🔌 [API Integration Guide](docs/api-integration.md) - For tool builders
- 🌍 [Cross-Platform Support](docs/cross-platform-support.md) - Platform-specific setup
- 🔒 [Privacy Policy](docs/privacy.md) - Data collection transparency

### Deployment
- 🚀 [Registry Deployment Guide](docs/registry/deployment.md) - Self-hosting options
- 🐳 [Docker Setup](docs/installation.md#registry-backend-self-hosted) - Container deployment

### For Developers
- 🏗️ [Architecture Overview](docs/internal/COMPAT_REGISTRY_PROJECT_ARCHITECTURE.md)
- 📋 [Design Proposal](docs/internal/TOOL_CALLING_REGISTRY_PROPOSAL.md)
- 🤝 [Contributing Guide](CONTRIBUTING.md)
- ✅ [Release Checklist](docs/internal/RELEASE_CHECKLIST.md)

## Requirements

- **Ollama** running locally (or accessible via `OLLAMA_HOST`)
- **Python 3.10+** (automatically handled by uvx/pipx)
- At least one model pulled in Ollama

## Example Output

```
🔍 Discovered 3 models locally:
  • qwen2.5-coder:7b
  • llama3:8b  
  • mistral:7b

Running compatibility checks...

✓ qwen2.5-coder:7b - Pass rate: 100% (4/4 passed)
  ✓ structured_tool_call: PASS
  ✓ json_in_content: PASS
  ✓ control_no_tools: PASS
  ✓ multiple_tools: PASS

⚠ llama3:8b - Pass rate: 75% (3/4 passed)
  ✓ structured_tool_call: PASS
  ⚠ json_in_content: FALLBACK (JSON in content field)
  ✓ control_no_tools: PASS
  ✓ multiple_tools: PASS

❌ mistral:7b - Pass rate: 0% (0/4 passed)
  ❌ structured_tool_call: REJECTED (backend refused tools)
  ❌ json_in_content: REJECTED
  ✓ control_no_tools: PASS
  ❌ multiple_tools: REJECTED
```

## API Integration

Query the public registry programmatically:

```python
import httpx

response = httpx.get("https://registry.caniollama.dev/models/qwen2.5-coder:7b")
data = response.json()
print(f"Pass rate: {data['pass_rate']:.0%}")
```

### Self-Hosted Registry

Run your own instance with Docker:

```bash
docker pull ghcr.io/anjalll/caniollama-registry:latest
docker run -p 8000:8000 ghcr.io/anjalll/caniollama-registry:latest
```

See [Installation Guide](docs/installation.md) and [API Integration Guide](docs/api-integration.md) for full documentation.

## Quick Development Setup

```bash
# CLI
cd compat-check && uv sync && uv run pytest

# Registry backend
cd compat-registry && uv sync && uv run pytest
uv run uvicorn compat_registry.main:app --reload   # http://localhost:8000/docs
```

## Contributing

Contributions welcome! Ways to help:

- 🧪 Run tests on your models and submit results
- 🐛 Report bugs or compatibility issues  
- 📝 Improve documentation
- 🎯 Suggest new test cases for the suite
- 🔧 Submit PRs for bug fixes or features

See [CONTRIBUTING.md](CONTRIBUTING.md) for guidelines.

## License

MIT License - see [LICENSE](LICENSE) for details.

## Related Projects

- [Ollama](https://ollama.ai) - Run LLMs locally

## Support

- 📫 [Open an issue](https://github.com/AnjalLLL/caniollama/issues)
- 💬 [Discussions](https://github.com/AnjalLLL/caniollama/discussions)
- 🔒 [Security policy](SECURITY.md) · [Code of Conduct](CODE_OF_CONDUCT.md) · [Changelog](CHANGELOG.md)

---

**Status:** Pre-1.0 (latest: see PyPI badge above)  
**Stars appreciated!** ⭐
