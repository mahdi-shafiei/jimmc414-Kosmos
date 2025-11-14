# Kosmos AI Scientist

> Autonomous AI scientist for hypothesis generation, experimental design, and iterative scientific discovery. Supports Claude, OpenAI, and local models.

[![Version](https://img.shields.io/badge/version-0.2.0-blue.svg)](https://github.com/jimmc414/Kosmos)
[![Status](https://img.shields.io/badge/status-production-blue.svg)](https://github.com/jimmc414/Kosmos)
[![Tests](https://img.shields.io/badge/tests-90%25%20coverage-blue.svg)](https://github.com/jimmc414/Kosmos)
[![Performance](https://img.shields.io/badge/performance-20--40×%20faster-blue.svg)](https://github.com/jimmc414/Kosmos)

Kosmos is an open-source implementation of an autonomous AI scientist that can conduct complete research cycles: from literature analysis and hypothesis generation through experimental design, execution, analysis, and iterative refinement.

**v0.2.0 Multi-Provider Release** - Now supports Anthropic Claude, OpenAI GPT, and local models (Ollama, LM Studio) with configuration-driven provider switching. Includes 20-40× performance improvements, comprehensive testing, and production deployment support.

## Features

### Core Capabilities
- **Autonomous Research Cycle**: Complete end-to-end scientific workflow
- **Multi-Domain Support**: Biology, physics, chemistry, neuroscience, materials science
- **Multi-Provider LLM Support**: Choose between Anthropic, OpenAI, or local models
- **Command-line Interface**: Rich terminal interface with 8 commands, interactive mode, and live progress
- **Agent-Based Architecture**: Modular agents for each research task
- **Safety-First Design**: Sandboxed execution, validation, reproducibility checks

### Multi-Provider LLM Support

Kosmos now supports multiple LLM providers, giving you flexibility in cost, privacy, and model selection:

| Provider | Type | Example Models | Privacy | Cost |
|----------|------|----------------|---------|------|
| **Anthropic** | Cloud | Claude 3.5 Sonnet, Opus, Haiku | Cloud | $$ |
| **OpenAI** | Cloud | GPT-4 Turbo, GPT-4, GPT-3.5, O1 | Cloud | $$$ |
| **Ollama** | Local | Llama 3.1, Mistral, Mixtral | **Private** | **Free** |
| **OpenRouter** | Aggregator | 100+ models | Cloud | Varies |
| **LM Studio** | Local | Any GGUF model | **Private** | **Free** |

**Switch providers with zero code changes** - just update your `.env` file:

```bash
# Use OpenAI instead of Anthropic
LLM_PROVIDER=openai
OPENAI_API_KEY=sk-...
OPENAI_MODEL=gpt-4-turbo

# Or run completely local with Ollama (free)
LLM_PROVIDER=openai
OPENAI_BASE_URL=http://localhost:11434/v1
OPENAI_MODEL=llama3.1:70b
```

**Benefits:**
- **Cost Flexibility**: Mix expensive/cheap models or use free local models
- **Privacy Options**: Run entirely locally for sensitive research
- **Provider Independence**: Switch based on availability, pricing, performance
- **Redundancy**: Mitigate rate limits and service disruptions
- **Access Specialized Models**: Domain-specific or fine-tuned models

**[Provider Setup Guide](docs/providers/README.md)** - Detailed instructions for all supported providers

### Performance & Scalability
- **20-40× Overall Performance**: Combined optimizations for significant speedup
- **Parallel Execution**: 4-16× faster experiments via ProcessPoolExecutor
- **Concurrent Operations**: 2-4× faster research cycles with async operations
- **Smart Caching**: Multi-tier caching reducing API costs by 30%+
- **Database Optimization**: 10× faster queries with strategic indexes
- **Auto-Scaling**: Kubernetes HorizontalPodAutoscaler support

### Production Features
- **Health Monitoring**: Prometheus metrics, alerts (email/Slack/PagerDuty)
- **Performance Profiling**: CPU, memory, bottleneck detection
- **Docker Deployment**: Complete docker-compose stack with all services
- **Kubernetes Ready**: 8 manifests for production deployment
- **Cloud Support**: Deployment guides for AWS, GCP, Azure
- **Comprehensive Testing**: 90%+ test coverage across all components

### Developer Experience
- **Flexible Integration**: Supports Anthropic Claude, OpenAI GPT, and local models (Ollama, LM Studio)
- **Proven Analysis Patterns**: Integrates battle-tested statistical methods
- **Literature Integration**: Automated paper search, summarization, and novelty checking
- **Rich Documentation**: 10,000+ lines across user guides, API docs, and examples

## Performance & Optimization

### Intelligent Caching System

Kosmos includes a sophisticated multi-tier caching system that reduces API costs by **30-40%**:

```bash
# View cache performance
kosmos cache --stats

# Example output:
# Overall Cache Performance:
#   Total Requests: 500
#   Cache Hits: 175 (35%)
#   Estimated Cost Savings: $15.75
```

**Cache Types**:
- **LLM Response Cache**: API response caching (25-35% hit rate with Anthropic prompt caching)
- **Experiment Cache**: Computational result caching (40-50% hit rate)
- **Embedding Cache**: Vector embedding caching (in-memory, fast)
- **General Cache**: Miscellaneous data caching

**Benefits**:
- Reduced API costs (30%+ savings)
- Faster response times (90%+ faster on cache hits)
- Improved reliability (cached responses always available)
- Lower environmental impact

**Note:** Prompt caching with significant cost savings is currently available when using Anthropic Claude. OpenAI and local providers use in-memory response caching only.

### Automatic Model Selection (Anthropic Only)

When using Anthropic as your LLM provider, Kosmos intelligently selects between Claude models based on task complexity:

- **Claude Sonnet 4.5**: Complex reasoning, hypothesis generation, analysis
- **Claude Haiku 4**: Simple tasks, data extraction, formatting

This reduces costs by **15-20%** while maintaining quality.

**Note:** This feature is specific to Anthropic Claude. OpenAI and other providers use a single configured model.

### Expected Performance

Typical research run characteristics (using Anthropic Claude):

- **Duration**: 30 minutes to 2 hours
- **Iterations**: 5-15 iterations
- **API Calls**: 50-200 calls
- **Cost**: $5-$50 with caching (without caching: $8-$75) **[Anthropic pricing]**
- **Cache Hit Rate**: 30-40% on subsequent runs **[Anthropic prompt caching]**

**Note:** Costs vary by provider. OpenAI pricing may differ. Local models (Ollama/LM Studio) have $0 API costs.

## Quick Start

### Prerequisites

- Python 3.11 or 3.12
- **LLM Provider** - Choose one:
  - **Anthropic Claude** (default) - API key (pay-per-use) or Claude Code CLI (Max subscription)
  - **OpenAI GPT** - API key for GPT models
  - **Ollama** - Free local models (no API key needed)
  - **Other providers** - See [Provider Setup Guide](docs/providers/README.md)

### Installation

```bash
# Clone the repository
git clone https://github.com/jimmc414/Kosmos.git
cd Kosmos

# Create virtual environment
python3.11 -m venv venv
source venv/bin/activate  # On Windows: venv\Scripts\activate

# Install dependencies
pip install -e .

# For Claude Code CLI support (Option B)
pip install -e ".[router]"
```

### Configuration

#### Option A: Using Anthropic API

```bash
# Copy example config
cp .env.example .env

# Edit .env and set your API key
# ANTHROPIC_API_KEY=sk-ant-api03-your-actual-key-here
```

Get your API key from [console.anthropic.com](https://console.anthropic.com/)

#### Option B: Using Claude Code CLI (Recommended)

```bash
# 1. Install Claude Code CLI
# Follow instructions at https://claude.ai/download

# 2. Authenticate Claude CLI
claude auth

# 3. Copy example config
cp .env.example .env

# 4. Edit .env and set API key to all 9s (triggers CLI routing)
# ANTHROPIC_API_KEY=999999999999999999999999999999999999999999999999
```

This routes all API calls to your local Claude Code CLI, using your Max subscription with no per-token costs.

### Initialize Database

```bash
# Run database migrations
alembic upgrade head

# Verify database created
ls -la kosmos.db
```

### Run Your First Research Project

#### Using the CLI (Recommended)

```bash
# Interactive mode with guided prompts
kosmos run --interactive

# Or provide a question directly
kosmos run "What is the relationship between sleep deprivation and memory consolidation?" \
  --domain neuroscience \
  --max-iterations 5

# Monitor progress in another terminal
kosmos status <run_id> --watch

# View research history
kosmos history --limit 10
```

#### Using Python API

```python
from kosmos import ResearchDirectorAgent

# Initialize the research director
director = ResearchDirectorAgent()

# Pose a research question
question = "What is the relationship between sleep deprivation and memory consolidation?"

# Run autonomous research
results = director.conduct_research(
    question=question,
    domain="neuroscience",
    max_iterations=5
)

# View results
print(results.summary)
print(results.key_findings)
```

## CLI Commands

Kosmos provides a command-line interface powered by [Typer](https://typer.tiangolo.com/) and [Rich](https://rich.readthedocs.io/).

### Core Commands

#### `kosmos run` - Execute Research

Run autonomous research on a scientific question:

```bash
# Interactive mode (guided prompts)
kosmos run --interactive

# Direct mode with options
kosmos run "Your research question here" \
  --domain biology \
  --max-iterations 10 \
  --budget 50 \
  --output results.json

# Options:
#   --interactive          Launch interactive configuration mode
#   --domain TEXT          Scientific domain (biology, neuroscience, etc.)
#   --max-iterations INT   Maximum research iterations (default: 10)
#   --budget FLOAT         Budget limit in USD
#   --no-cache            Disable caching
#   --output PATH         Export results (JSON or Markdown)
```

#### `kosmos status` - Monitor Research

View research run status and progress:

```bash
# Show current status
kosmos status run_12345

# Watch mode (live updates every 5 seconds)
kosmos status run_12345 --watch

# Detailed view
kosmos status run_12345 --details

# Options:
#   --watch, -w    Live status updates
#   --details, -d  Show detailed information
```

#### `kosmos history` - Browse Past Research

Browse and search research history:

```bash
# Show recent runs
kosmos history

# Filter by domain
kosmos history --domain neuroscience --limit 20

# Filter by status
kosmos history --status completed --days 7

# Detailed view
kosmos history --details

# Options:
#   --limit INT     Number of runs to show (default: 10)
#   --domain TEXT   Filter by scientific domain
#   --status TEXT   Filter by state (completed, running, failed)
#   --days INT      Show runs from last N days
#   --details       Show detailed information for each run
```

#### `kosmos cache` - Manage Caching

View cache statistics and manage cached data:

```bash
# Show cache statistics
kosmos cache --stats

# Health check
kosmos cache --health

# Optimize (cleanup expired entries)
kosmos cache --optimize

# Clear specific cache
kosmos cache --clear-type claude

# Clear all caches
kosmos cache --clear

# Options:
#   --stats, -s           Show cache statistics
#   --health, -h          Run health check
#   --optimize, -o        Optimize and cleanup caches
#   --clear, -c           Clear all caches (requires confirmation)
#   --clear-type TEXT     Clear specific cache type
```

### Utility Commands

#### `kosmos config` - Configuration Management

View and validate configuration:

```bash
# Show current configuration
kosmos config --show

# Validate configuration
kosmos config --validate

# Show config file locations
kosmos config --path

# Options:
#   --show, -s       Display current configuration
#   --validate, -v   Validate configuration and check requirements
#   --path, -p       Show configuration file paths
```

#### `kosmos doctor` - System Diagnostics

Run diagnostic checks:

```bash
kosmos doctor

# Checks:
#   - Python version
#   - Required packages
#   - API key configuration
#   - Cache directory permissions
#   - Database connectivity
```

#### `kosmos version` - Version Information

Show version and system information:

```bash
kosmos version

# Displays:
#   - Kosmos version
#   - Python version
#   - Platform information
#   - LLM provider and SDK version
```

#### `kosmos info` - System Status

Show system status and configuration:

```bash
kosmos info

# Displays:
#   - Configuration settings
#   - Cache status and size
#   - API key status
#   - Enabled domains
```

## Architecture

```
┌────────────────────────────────────────────────────────────────┐
│                          CLI Layer                              │
│  (Typer + Rich: Interactive UI, Commands, Progress)            │
└─────────────────────┬──────────────────────────────────────────┘
                      │
┌─────────────────────▼──────────────────────────────────────────┐
│                    Research Director                            │
│  (Orchestrates workflow, manages state, coordinates agents)    │
└───┬───────────┬───────────┬──────────────┬───────────┬─────────┘
    │           │           │              │           │
    ▼           ▼           ▼              ▼           ▼
┌────────┐ ┌────────┐ ┌──────────┐ ┌─────────┐ ┌───────────────┐
│Hypoth  │ │Experi  │ │   Data   │ │Litera   │ │  Other        │
│esis    │ │ment    │ │ Analyst  │ │ture     │ │  Specialized  │
│Generat │ │Designer│ │          │ │Analyzer │ │  Agents       │
└────┬───┘ └────┬───┘ └────┬─────┘ └────┬────┘ └───────┬───────┘
     │          │          │             │             │
     └──────────┴──────────┴─────────────┴─────────────┘
                           │
          ┌────────────────┴────────────────────┐
          │                                     │
      ┌───▼───────┐                    ┌────────▼──────┐
      │ LLM Client│                    │   Execution   │
      │Multi-Provider│                 │    Engine     │
      └───┬───────┘                    └────────┬──────┘
          │                                     │
      ┌───▼──────────────┐              ┌──────▼────────┐
      │  Cache Manager   │              │Docker Sandbox │
      │ (30%+ savings)   │              │ (Code Safety) │
      └──────────────────┘              └───────────────┘
                           │
          ┌────────────────┴──────────────────┐
          │                                   │
      ┌───▼──────┐                    ┌───────▼─────┐
      │Neo4j KB  │                    │SQLite/Postgres│
      │  Graph   │                    │   Database    │
      └──────────┘                    └───────────────┘
```

### Core Components

- **CLI Layer**: Terminal UI with Rich and Typer for interactive research
- **Research Director**: Master orchestrator managing research workflow
- **Literature Analyzer**: Searches and analyzes scientific papers (arXiv, Semantic Scholar, PubMed)
- **Hypothesis Generator**: Uses configured LLM to generate testable hypotheses
- **Experiment Designer**: Designs computational experiments
- **Execution Engine**: Runs experiments using proven statistical methods
- **Data Analyst**: Interprets results using configured LLM
- **Cache Manager**: Multi-tier caching system for cost optimization
- **Feedback Loop**: Iteratively refines hypotheses based on results

## Anthropic Usage Modes

*For setup instructions for OpenAI, Ollama, OpenRouter, and LM Studio, see [Provider Setup Guide](docs/providers/README.md)*

### Mode 1: Claude Code CLI (Max Subscription)

**Pros:**
- No per-token costs
- Unlimited usage
- Latest Claude model
- Local execution

**Cons:**
- Requires Claude CLI installation
- Requires Max subscription

**Setup:**
```bash
pip install -e ".[router]"
# Set ANTHROPIC_API_KEY=999999999999999999999999999999999999999999999999
```

### Mode 2: Anthropic API

**Pros:**
- Pay-as-you-go
- No CLI installation needed
- Works anywhere

**Cons:**
- Per-token costs
- Rate limits apply

**Setup:**
```bash
# Set ANTHROPIC_API_KEY=sk-ant-api03-your-key-here
```

## Configuration

All configuration is via environment variables (see `.env.example`):

### LLM Provider Settings
- `LLM_PROVIDER`: Provider to use (`anthropic` or `openai`, default: `anthropic`)

### Anthropic Settings (when LLM_PROVIDER=anthropic)
- `ANTHROPIC_API_KEY`: API key or `999...` for CLI mode
- `CLAUDE_MODEL`: Model to use (default: `claude-3-5-sonnet-20241022`)
- `CLAUDE_MAX_TOKENS`: Max tokens per request (default: 4096)
- `CLAUDE_TEMPERATURE`: Sampling temperature 0.0-1.0 (default: 0.7)
- `CLAUDE_ENABLE_CACHE`: Enable prompt caching (default: true)

### OpenAI Settings (when LLM_PROVIDER=openai)
- `OPENAI_API_KEY`: OpenAI API key (required)
- `OPENAI_MODEL`: Model name (default: `gpt-4-turbo`)
- `OPENAI_MAX_TOKENS`: Max tokens per request (default: 4096)
- `OPENAI_TEMPERATURE`: Sampling temperature 0.0-2.0 (default: 0.7)
- `OPENAI_BASE_URL`: Custom base URL for compatible APIs (optional, for Ollama/OpenRouter/LM Studio)
- `OPENAI_ORGANIZATION`: OpenAI organization ID (optional)

### Core Settings
- `DATABASE_URL`: Database connection string
- `LOG_LEVEL`: Logging verbosity

### Research Settings
- `MAX_RESEARCH_ITERATIONS`: Max autonomous iterations
- `ENABLED_DOMAINS`: Which scientific domains to support
- `ENABLED_EXPERIMENT_TYPES`: Types of experiments allowed
- `MIN_NOVELTY_SCORE`: Minimum novelty threshold

### Safety Settings
- `ENABLE_SAFETY_CHECKS`: Code safety validation
- `MAX_EXPERIMENT_EXECUTION_TIME`: Timeout for experiments
- `ENABLE_SANDBOXING`: Sandbox code execution
- `REQUIRE_HUMAN_APPROVAL`: Manual approval gates

## Development

### Running Tests

```bash
# Install dev dependencies
pip install -e ".[dev]"

# Run all tests
pytest

# Run with coverage
pytest --cov=kosmos --cov-report=html

# Run specific test suite
pytest tests/unit/
pytest tests/integration/
pytest tests/e2e/
```

### Code Quality

```bash
# Format code
black kosmos/ tests/

# Lint
ruff check kosmos/ tests/

# Type check
mypy kosmos/
```

### Project Structure

```
kosmos/
├── core/           # Core infrastructure (LLM, config, logging)
├── agents/         # Agent implementations
├── db/             # Database models and operations
├── execution/      # Experiment execution engine
├── analysis/       # Result analysis and visualization
├── hypothesis/     # Hypothesis generation and management
├── experiments/    # Experiment templates
├── literature/     # Literature search and analysis
├── knowledge/      # Knowledge graph and semantic search
├── domains/        # Domain-specific tools (biology, physics, etc.)
├── safety/         # Safety checks and validation
└── cli/            # Command-line interface

tests/
├── unit/           # Unit tests
├── integration/    # Integration tests
└── e2e/            # End-to-end tests

docs/
├── kosmos-figures-analysis.md  # Analysis patterns from kosmos-figures
├── integration-plan.md         # Integration strategy
└── domain-roadmaps/            # Domain-specific guides
```

## Documentation

- [Architecture Overview](docs/architecture.md) - System design and components
- [Integration Plan](docs/integration-plan.md) - How we integrate kosmos-figures patterns
- [Domain Roadmaps](docs/domain-roadmaps/) - Domain-specific implementation guides
- [API Reference](docs/api/) - API documentation
- [Contributing Guide](CONTRIBUTING.md) - How to contribute

## Roadmap

### Phase 1: Core Infrastructure (Current)
- [x] Project structure
- [x] Claude integration (API + CLI)
- [ ] Configuration system
- [ ] Agent framework
- [ ] Database setup

### Phase 2: Knowledge & Literature
- [ ] Literature APIs (arXiv, Semantic Scholar, PubMed)
- [ ] Literature analyzer agent
- [ ] Vector database for semantic search
- [ ] Knowledge graph

### Phase 3: Hypothesis Generation
- [ ] Hypothesis generator agent
- [ ] Novelty checking
- [ ] Hypothesis prioritization

### Phase 4: Experimental Design
- [ ] Experiment designer agent
- [ ] Protocol templates
- [ ] Resource estimation

### Phase 5: Execution
- [ ] Sandboxed execution environment
- [ ] Integration of kosmos-figures patterns
- [ ] Statistical analysis

### Phase 6: Analysis & Interpretation
- [ ] Data analyst agent
- [ ] Visualization generation
- [ ] Result summarization

### Phase 7: Iterative Learning
- [ ] Research director agent
- [ ] Feedback loops
- [ ] Convergence detection

### Phases 8-10: Safety, Multi-Domain, Production
- [ ] Safety validation
- [ ] Domain-specific tools
- [ ] Production deployment

## Based On

This project is inspired by:
- **Paper**: [Kosmos: An AI Scientist for Autonomous Discovery](https://arxiv.org/pdf/2511.02824) (Nov 2025)
- **Analysis Patterns**: [kosmos-figures repository](https://github.com/EdisonScientific/kosmos-figures)
- **Claude Router**: [claude_n_codex_api_proxy](https://github.com/jimmc414/claude_n_codex_api_proxy)

## Contributing

Contributions welcome! See [CONTRIBUTING.md](CONTRIBUTING.md) for guidelines.

### Areas We Need Help

- Domain-specific tools and APIs
- Experiment templates for different domains
- Literature API integrations
- Safety validation
- Documentation
- Testing

## License

MIT License - see [LICENSE](LICENSE) for details.

## Citation

If you use Kosmos in your research, please cite:

```bibtex
@software{kosmos_ai_scientist,
  title={Kosmos AI Scientist: Multi-Provider Autonomous Scientific Discovery},
  author={Kosmos Contributors},
  year={2025},
  url={https://github.com/jimmc414/Kosmos}
}
```

## Acknowledgments

- **Anthropic** for Claude and Claude Code CLI
- **OpenAI** for GPT models and API
- **Ollama** for local model infrastructure
- **Edison Scientific** for kosmos-figures analysis patterns
- **Open science community** for literature APIs and tools

## Support

- **Issues**: [GitHub Issues](https://github.com/jimmc414/Kosmos/issues)
- **Discussions**: [GitHub Discussions](https://github.com/jimmc414/Kosmos/discussions)

---

**Status**: v0.2.0 - Multi-Provider Support Released

**Recent Updates**:
- Multi-provider LLM support (Anthropic, OpenAI, Ollama, OpenRouter, LM Studio)
- Provider abstraction layer with unified API
- Comprehensive provider documentation and migration guides
- Configuration-driven provider switching
- Performance optimization (20-40× faster)
- Production deployment features

**Last Updated**: 2025-11-13
