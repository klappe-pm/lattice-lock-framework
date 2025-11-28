# Model Orchestration Agent System

## 🚀 Overview

A sophisticated **Model Orchestration Agent** that intelligently routes tasks across **63 AI models** from **8 providers** with:

- **Intelligent Model Selection**: Automatically selects the best model based on task requirements
- **Cost Optimization**: Tracks and optimizes costs across providers
- **Multi-Model Patterns**: Chain, parallel, consensus, and hierarchical interactions
- **Zen MCP Integration**: Seamlessly works with existing Zen MCP tools
- **Complete Provider Coverage**: All major AI providers plus 20 local models

## 🏗️ Architecture

```
┌─────────────────────────────────────────────┐
│           Model Orchestrator CLI            │
└─────────────────┬───────────────────────────┘
                  │
        ┌─────────▼─────────┐
        │   Model Router    │
        └─────────┬─────────┘
                  │
    ┌─────────────┴─────────────┐
    │                           │
┌───▼────┐              ┌───────▼──────┐
│Zen MCP │              │Model         │
│Bridge  │              │Orchestrator  │
└───┬────┘              └───────┬──────┘
    │                           │
┌───▼────────────────────────────▼────┐
│      63 Models Across 8 Providers   │
│  ┌──────┐ ┌──────┐ ┌──────┐ ┌────┐  │
│  │Local │ │OpenAI│ │Bedrk │ │Anth│  │
│  │(20)  │ │(11)  │ │(8)   │ │(7) │  │
│  └──────┘ └──────┘ └──────┘ └────┘  │
│  ┌──────┐ ┌──────┐ ┌──────┐ ┌────┐  │
│  │Google│ │Grok  │ │Azure │ │DIAL│  │
│  │(6)   │ │(5)   │ │(4)   │ │(2) │  │
│  └──────┘ └──────┘ └──────┘ └────┘  │
└──────────────────────────────────────┘
```

## 📦 Components

### 1. **model_orchestrator.py**

Core orchestration engine with:

- Task analysis and requirements detection
- Model capability scoring (0-1 scale)
- Cost tracking and optimization
- Performance history tracking

### 2. **zen_mcp_bridge.py**

Bridges orchestrator with Zen MCP:

- Extends Zen tools with all models
- Intelligent tool-to-model mapping
- Multi-model consensus support
- Adaptive analysis depth

### 3. **orchestrator_cli.py**

Command-line interface:

- List and analyze models
- Route requests intelligently
- Create consensus groups
- Track costs and usage

### 4. **grok_api.py** + **grok.sh**

Direct Grok API access:

- All 5 Grok models available
- Vision capabilities (grok-2-vision-1212)
- 2M context window support (grok-4 variants)

## 🎯 Key Features

### Intelligent Model Selection

The system scores models based on:

- **Task Affinity** (40%): How well suited for the task type
- **Performance** (30%): Speed vs reasoning depth tradeoff
- **Accuracy** (20%): Model accuracy rating
- **Cost Efficiency** (10%): Price/performance ratio

### Task Types Detected

- `CODE_GENERATION`: Writing code
- `CODE_REVIEW`: Reviewing/analyzing code
- `REASONING`: Complex reasoning tasks
- `VISION`: Image analysis
- `DEBUGGING`: Finding and fixing bugs
- `SYSTEM_DESIGN`: Architecture planning
- `CREATIVE_WRITING`: Stories, poems
- `ANALYSIS`: Data/system analysis
- `TRANSLATION`: Language translation
- `SUMMARIZATION`: Text summarization

### Multi-Model Interaction Patterns

#### 1. **Chain Of Thought**

Sequential processing through multiple models:

```python
chain = orchestrator.create_model_chain(tasks)
```

#### 2. **Parallel Consensus**

Multiple models vote on the answer:

```python
consensus = orchestrator.create_consensus_group(prompt, num_models=3)
```

#### 3. **Hierarchical Refinement**

Start cheap, refine with better models:

```python
result = await hierarchical_refinement(prompt, refinements)
```

#### 4. **Adaptive Analysis**

Depth adjusts to complexity:

```python
result = await adaptive_analysis(prompt, depth="auto")
```

## 🚦 Usage

### CLI Commands

```bash
# List all models with details
./orchestrator_cli.py list --verbose

# Analyze a prompt to see model selection
./orchestrator_cli.py analyze "Write a Python web server"

# Route a request with specific strategy
./orchestrator_cli.py route "Explain quantum computing" --strategy quality_first

# Create consensus group
./orchestrator_cli.py consensus "What's the best database for this project?" --num 5

# Show cost report
./orchestrator_cli.py cost

# Test integration
./orchestrator_cli.py test
```

### Python API

```python
from model_orchestrator import ModelOrchestrator
from zen_mcp_bridge import ModelRouter

# Initialize
orchestrator = ModelOrchestrator()
router = ModelRouter()

# Select best model
model_id, model = orchestrator.select_model(
    "Write a sorting algorithm",
    strategy="balanced"  # or cost_optimize, quality_first, speed_priority
)

# Route through system
result = await router.route(
    "Analyze this complex problem",
    mode="consensus",  # or auto, chain, adaptive
    num_models=3
)

# Track costs
orchestrator.track_usage(model_id, input_tokens=1000, output_tokens=500, latency_ms=250)
report = orchestrator.get_cost_report()
```

## 📊 Model Capabilities (63 Total Models)

### Local Models (20 models - FREE)

| Model | Size | RAM | Best For | Speed | Quality |
|-------|------|-----|----------|-------|---------|
| deepseek-r1:70b | 42GB | ~35GB | **Ultimate reasoning** | ⚡ | ⭐⭐⭐⭐⭐ |
| codellama:34b | 19GB | ~30GB | **Best code quality** | ⚡ | ⭐⭐⭐⭐⭐ |
| qwen2.5:32b | 19GB | ~25GB | Premium intelligence | ⚡ | ⭐⭐⭐⭐⭐ |
| codellama:13b | 7.4GB | ~12GB | High-quality code | ⚡⚡ | ⭐⭐⭐⭐ |
| magicoder:7b | 3.8GB | ~8GB | **Optimal code balance** | ⚡⚡ | ⭐⭐⭐⭐ |
| qwen3:8b | 5.2GB | ~10GB | Multilingual, reasoning | ⚡⚡ | ⭐⭐⭐⭐ |
| llama3.1:8b | 4.9GB | ~8GB | General tasks | ⚡⚡ | ⭐⭐⭐ |
| llama3.2:3b | 2.0GB | ~4GB | Fast conversations | ⚡⚡⚡ | ⭐⭐⭐ |
|| deepseek-coder:1.3b | 776MB | ~2GB | Quick code snippets | ⚡⚡⚡ | ⭐⭐⭐ |
|| gemma:7b | 5.0GB | ~8GB | **Google's balanced model** | ⚡⚡ | ⭐⭐⭐⭐ |
|| qwen2.5:7b-instruct | 4.7GB | ~8GB | **Instruction-tuned Qwen** | ⚡⚡ | ⭐⭐⭐⭐ |

### OpenAI Models (11 models)

| Model | Context | Best For | Cost (I/O) per M tokens |
|-------|---------|----------|-------------------------|
| o1-pro | 200K | **Ultimate reasoning** | $60/$240 |
| o1 | 200K | Deep reasoning | $15/$60 |
| o1-mini | 200K | Balanced reasoning | $3/$12 |
| gpt-4o | 128K | Vision, balanced tasks | $5/$15 |
| gpt-4-turbo | 128K | Vision, function calling | $10/$30 |
| gpt-4 | 8K | Complex reasoning | $30/$60 |
| gpt-4o-mini | 128K | Fast, cost-effective | $0.15/$0.6 |
| gpt-3.5-turbo | 16K | Quick tasks | $0.5/$1.5 |

### Bedrock Models (8 models)

| Model | Context | Best For | Cost (I/O) per M tokens |
|-------|---------|----------|-------------------------|
| bedrock-claude-3-opus | 200K | Premium reasoning | $15/$75 |
| bedrock-claude-3.5-sonnet | 200K | Balanced Claude | $3/$15 |
| bedrock-llama-3.1-405b | 32K | Massive model power | $5.32/$16 |
| bedrock-llama-3.1-70b | 32K | Strong reasoning | $2.65/$3.5 |
| bedrock-titan-text-express | 8K | AWS native | $0.8/$1.6 |

### Anthropic Models (7 models)

| Model | Context | Best For | Cost (I/O) per M tokens |
|-------|---------|----------|-------------------------|
| claude-opus-4.1 | 200K | **Top reasoning** | $20/$100 |
| claude-opus-4 | 200K | Premium Claude | $15/$75 |
| claude-sonnet-4.5 | 200K | Latest balanced | $4/$20 |
| claude-sonnet-4 | 200K | Balanced tasks | $3/$15 |
| claude-3-opus | 200K | Previous gen premium | $15/$75 |
| claude-3.5-sonnet | 200K | Popular balanced | $3/$15 |
| claude-3-haiku | 200K | Fast, cost-effective | $0.25/$1.25 |

### Google Gemini (6 models)

| Model | Context | Best For | Cost (I/O) per M tokens |
|-------|---------|----------|-------------------------|
| gemini-2.0-pro | **2M** | Research, analysis | $1.5/$6 |
| gemini-2.0-flash | **1M** | Fast responses | $0.1/$0.4 |
| gemini-1.5-pro | **2M** | Previous gen pro | $1.25/$5 |
| gemini-1.5-flash | **1M** | Previous gen flash | $0.075/$0.3 |

### xAI Grok (5 models)

| Model | Context | Best For | Cost (I/O) per M tokens |
|-------|---------|----------|-------------------------|
| grok-4-fast-reasoning | **2M** | Complex reasoning | $2/$6 |
| grok-4-fast-non-reasoning | **2M** | Fast processing | $1/$3 |
| grok-code-fast-1 | 256K | Code generation | $1.5/$4.5 |
| grok-3 | 131K | General tasks | $1/$3 |
| grok-2-vision-1212 | 32K | Image analysis | $2/$6 |

### Azure OpenAI (4 models)

| Model | Context | Best For | Cost (I/O) per M tokens |
|-------|---------|----------|-------------------------|
| azure-gpt-4o | 128K | Enterprise GPT-4o | $5/$15 |
| azure-gpt-4-turbo | 128K | Enterprise GPT-4 Turbo | $10/$30 |
| azure-gpt-4 | 8K | Enterprise GPT-4 | $30/$60 |
| azure-claude-3.5-sonnet | 200K | Enterprise Claude | $3/$15 |

### DIAL Gateway (2 models)

| Model | Context | Best For | Cost (I/O) per M tokens |
|-------|---------|----------|-------------------------|
| dial-claude-opus-4 | 200K | Enterprise access | $15/$75 |
| dial-claude-sonnet-4 | 200K | Enterprise balanced | $3/$15 |

## 🔧 Configuration

### Environment Variables

```bash
# Required for providers
export XAI_API_KEY="your-grok-key"
export OPENAI_API_KEY="your-openai-key"
export GOOGLE_API_KEY="your-google-key"
export DIAL_API_KEY="your-dial-key"
export ANTHROPIC_API_KEY="your-anthropic-key"

# Optional
export CUSTOM_API_URL="http://localhost:11434/v1"  # For local models
```

### Strategies

- **`balanced`**: Default, balances all factors
- **`cost_optimize`**: Minimize costs
- **`quality_first`**: Maximize accuracy/reasoning
- **`speed_priority`**: Fastest response time

## 🎨 Advanced Features

### Cost Tracking

```python
# Get detailed cost breakdown
report = orchestrator.get_cost_report()
# Returns: total_cost, by_model, by_provider, usage_count
```

### Custom Task Requirements

```python
from model_orchestrator import TaskRequirements, TaskType

requirements = TaskRequirements(
    task_type=TaskType.CODE_GENERATION,
    min_context_window=100000,
    requires_vision=False,
    requires_reasoning=True,
    max_cost=0.10,
    preferred_providers=[ModelProvider.XAI]
)

model_id, model = orchestrator.select_model_with_requirements(requirements)
```

### Zen MCP Extension

The bridge automatically extends Zen MCP tools with optimal model selection:

```python
# Zen tool automatically selects best model
result = await bridge.intelligent_zen_call(
    "mcp__zen__thinkdeep",
    prompt,
    auto_select_model=True  # Orchestrator chooses
)
```

## 🧪 Testing

Run the integration test:

```bash
./orchestrator_cli.py test
```

This validates:

- Model availability
- Task detection accuracy
- Strategy-based selection
- Zen MCP integration
- Cost tracking

## 📈 Performance

- **Model Selection**: <10ms
- **Task Analysis**: <5ms
- **Consensus Group**: <20ms
- **Cost Calculation**: <1ms

## 🚀 Quick Start

1. **Set API Keys**

```bash
export XAI_API_KEY="..."
export OPENAI_API_KEY="..."
# etc.
```

2. **Test the system**

```bash
./orchestrator_cli.py test
```

3. **Analyze a task**

```bash
./orchestrator_cli.py analyze "Your task here"
```

4. **Route a request**

```bash
./orchestrator_cli.py route "Your prompt" --strategy balanced
```

## 🔮 Future Enhancements

- [ ] Real API integration (currently mock)
- [ ] Learning from usage patterns
- [ ] Custom model definitions
- [ ] Streaming support
- [ ] Batch processing
- [ ] Web UI dashboard
- [ ] Model fine-tuning recommendations
- [ ] Automatic fallback chains

## 📝 License

MIT License - Use freely in your projects

---

**Built with intelligence** - This orchestrator ensures you always use the right model for the right task at the right price.
