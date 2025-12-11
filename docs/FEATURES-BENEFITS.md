# Features & Benefits by Audience

MCP Audit v0.5.0 - Features mapped to benefits for each target audience.

---

## At a Glance

| Feature | MCP Tool Developers | AI Coding Power Users |
|---------|---------------------|----------------------|
| Real-time TUI | See tool efficiency live | Watch context consumption |
| Per-tool metrics | Benchmark your implementations | Find expensive tools |
| Per-server breakdown | Isolate server-level issues | Compare MCP server costs |
| Built-in tool tracking | Monitor CLI-native tools | See total tool usage |
| Cache analysis | Optimize cache behavior | Understand cache efficiency |
| Duplicate detection | Find redundant API calls | Spot wasted tokens |
| Cross-session reports | Track optimization progress | Long-term cost trends |
| Cost estimation | Price your tools accurately | Budget planning |
| Privacy-first design | Safe to use in production | No data leaves your machine |
| **Smell detection** (v0.5.0) | Find anti-patterns in your tools | Identify inefficient usage |
| **AI prompt export** (v0.5.0) | Export for automated analysis | Let AI analyze your sessions |
| **Zombie tool detection** (v0.5.0) | Find unused tools in schema | Reduce context overhead |
| **Data quality indicators** (v0.5.0) | Know estimation accuracy | Understand data confidence |

---

## v0.5.0 Features: Insight Layer

v0.5.0 introduces the "Insight Layer" — automatic detection of efficiency anti-patterns, AI-exportable session data, and data quality indicators.

### Smell Detection Engine

Automatically detect 5 efficiency anti-patterns during sessions:

| Pattern | Severity | Threshold | What It Means |
|---------|----------|-----------|---------------|
| `HIGH_VARIANCE` | warning | CV > 50% | Token counts vary wildly — consider batching |
| `TOP_CONSUMER` | info | >50% of tokens | Single tool dominates — investigate or optimize |
| `HIGH_MCP_SHARE` | info | >80% of tokens | Heavy MCP reliance — may be opportunity to use built-ins |
| `CHATTY` | warning | >20 calls | Too many calls — consider batching or caching |
| `LOW_CACHE_HIT` | warning | <30% ratio | Cache underutilized — reorder operations for reuse |

Smells appear in session logs with severity, description, and evidence:
```json
{
  "smells": [
    {
      "pattern": "CHATTY",
      "severity": "warning",
      "tool": "mcp__zen__chat",
      "description": "Called 25 times",
      "evidence": {"call_count": 25, "threshold": 20}
    }
  ]
}
```

### AI Prompt Export

Export session data for analysis by your AI assistant:

```bash
# Export as structured markdown
mcp-audit export ai-prompt

# Export as JSON for programmatic use
mcp-audit export ai-prompt --format json
```

The export includes:
- Session summary (tokens, costs, duration)
- Top tools by token consumption
- Detected smells with evidence
- Data quality indicators
- Suggested analysis questions

### Zombie Tool Detection

Identify MCP tools defined in server schemas but never called:

```toml
# mcp-audit.toml
[zombie_tools.zen]
tools = [
    "mcp__zen__thinkdeep",
    "mcp__zen__debug",
    "mcp__zen__refactor"
]
```

Session logs report unused tools per server:
```json
{
  "zombie_tools": {
    "zen": ["mcp__zen__refactor", "mcp__zen__precommit"]
  }
}
```

Each unused tool's schema contributes to context overhead without providing value.

### Data Quality Indicators

Every session now includes accuracy metadata:

```json
{
  "data_quality": {
    "accuracy_level": "estimated",
    "token_source": "tiktoken",
    "token_encoding": "o200k_base",
    "confidence": 0.99,
    "notes": "Tokens estimated using tiktoken o200k_base (~99% accuracy)"
  }
}
```

| Accuracy Level | Description | Platforms |
|----------------|-------------|-----------|
| `exact` | Native platform tokens | Claude Code |
| `estimated` | Tokenizer-based estimation | Codex CLI, Gemini CLI |
| `calls-only` | Only call counts, no tokens | Future Ollama CLI |

---

## Audience 1: MCP Tool Developers

**Profile**: You build MCP servers (hand-coded or via AI CLI agents). You need data to optimize your implementations before shipping. You're investigating context bloat and high token usage in your tools.

### Core Benefits

| You Need | Feature | How It Helps |
|----------|---------|--------------|
| Know if your tools are efficient | **Per-tool token metrics** | See exact token consumption per tool call |
| Compare tool versions | **Cross-session analysis** | Track improvements across development cycles |
| Find bloated tools | **Top expensive tools ranking** | Instantly identify the worst offenders |
| Optimize cache behavior | **Cache analysis with AI-readable breakdown** | See which tools drive cache creation vs reuse |
| Catch redundant API patterns | **Duplicate detection** | Find repeated identical calls automatically |
| Ship with confidence | **Anomaly detection** | Get warnings for high-variance or high-frequency patterns |
| Investigate context bloat | **Server pinning** | Pin your server to monitor it closely during development |

### Key Features for Developers

**1. Per-Tool Token Breakdown**
```
Tool                              Calls    Tokens    Avg/Call
mcp__myserver__heavy_tool            12   450,231      37,519
mcp__myserver__light_tool            45    12,345         274
```
- Compare tool efficiency within your server
- Identify which tools need optimization
- Benchmark against expected performance

**2. Cache Analysis (AI-Readable)**
```json
{
  "cache_analysis": {
    "status": "inefficient",
    "top_cache_creators": [{"tool": "mcp__myserver__fetch", "tokens": 50000, "pct": 80}],
    "recommendation": "Consider batching related queries to reuse cached context."
  }
}
```
- Understand cache creation vs read patterns
- Get actionable recommendations
- Optimize for Anthropic's cache pricing model

**3. Duplicate Detection**
```json
{
  "redundancy_analysis": {
    "duplicate_calls": 3,
    "potential_savings": 15234,
    "details": [{"tool": "mcp__myserver__search", "count": 2, "tokens": 8765}]
  }
}
```
- Find identical tool calls that could be cached
- Quantify potential token savings
- Improve tool design to avoid redundancy

**4. Cross-Session Trend Analysis**
```bash
mcp-audit report ~/.mcp-audit/sessions/ --format csv --output analysis.csv
```
- Track optimization progress over time
- Compare before/after metrics
- Export to spreadsheet for deeper analysis

### Developer Workflow

```bash
# 1. Track while developing
mcp-audit collect --platform claude-code --pin-server myserver

# 2. Work with your MCP tools
# (Real-time TUI shows per-tool metrics)

# 3. Review session results
mcp-audit report ~/.mcp-audit/sessions/

# 4. Iterate and improve
# (Track new sessions to verify optimizations)
```

---

## Audience 2: AI Coding Power Users

**Profile**: You use Claude Code, Codex CLI, or Gemini CLI daily. You've hit context limits or seen unexpected costs. You want visibility.

### Core Benefits

| You Need | Feature | How It Helps |
|----------|---------|--------------|
| Know what's eating context | **Real-time TUI** | Watch tokens flow as you work |
| Find expensive MCP tools | **Per-server breakdown** | See exactly which servers cost most |
| Stay under context limits | **Cache efficiency tracking** | Understand how much context is reused |
| Control costs | **Cost estimation** | See estimated spend in real-time |
| Make informed tool choices | **Top tools ranking** | Know which tools to use sparingly |
| Understand usage patterns | **Cross-session reports** | Spot trends across your workflow |

### Key Features for Power Users

**1. Real-Time TUI Dashboard**
```
MCP Audit - Live Session
-------------------------------------------
Project: my-project | Platform: claude-code
Elapsed: 12m 34s | Model: claude-opus-4-5

Tokens:  45,231 input | 12,543 output | 125K cached
Cost:    $0.12 (estimated)
Cache:   93% efficiency | Savings: $0.89

MCP Servers & Tools (42 calls)
  zen (28 calls, 234K tokens)
    chat ............ 15 calls, 45K tokens
    thinkdeep ....... 8 calls, 156K tokens
    debug ........... 5 calls, 33K tokens
  brave-search (14 calls, 89K tokens)
    brave_web_search  14 calls, 89K tokens
```
- See everything at a glance
- No manual tracking or spreadsheets
- Updates in real-time as you work

**2. Cost Estimation**
```
Estimated Cost:  $0.12
```
- Real-time cost tracking based on model pricing
- Configurable pricing for different models
- Cache savings factored in

**3. Cache Efficiency Insights**
```
Cache efficiency:  93%
Cache Savings:    $0.89

(or if inefficient)
Net Cost:         $0.05 (high creation, low reuse)
```
- Understand whether cache is helping or hurting
- See potential savings from cache hits
- Know when to optimize query patterns

**4. Server-Level Breakdown**
```
MCP Servers & Tools
  zen (28 calls, 234K tokens) ............... 72%
  brave-search (14 calls, 89K tokens) ....... 28%
```
- Compare costs across different MCP servers
- Make informed decisions about which servers to use
- Pin servers you want to monitor closely

**5. Session Summary on Exit**
```
Session Complete
-------------------------------------------
Duration:     45m 12s
Total Tokens: 1,234,567
  Input:      456,789
  Output:     123,456
  Cached:     654,322

Estimated Cost: $2.34
Cache Savings:  $1.56

Top Tools:
  mcp__zen__thinkdeep ...... 450K tokens (36%)
  mcp__brave-search__web ... 123K tokens (10%)
```
- Clear summary when you're done
- Useful for comparing sessions
- Export for team sharing

### Power User Workflow

```bash
# 1. Start mcp-audit BEFORE starting Claude Code
mcp-audit collect --platform claude-code

# 2. Work normally in Claude Code
# (Real-time TUI shows token consumption)

# 3. Stop with Ctrl+C when done
# (Session saved automatically)

# 4. Review weekly/monthly patterns
mcp-audit report ~/.mcp-audit/sessions/
```

---

## Platform-Specific Benefits

### Claude Code Users

| Feature | Benefit |
|---------|---------|
| Cache tracking | Understand Anthropic's cache efficiency |
| Context limit visibility | Know when you're approaching limits |
| Model detection | See which Claude model is being used |
| Session file monitoring | Zero-config automatic tracking |
| Built-in tool summary | Track Bash, Read, Edit, Glob usage in session files |

**Pain Point Addressed**: "Why did I hit the context limit?"

### Codex CLI Users

| Feature | Benefit |
|---------|---------|
| Direct cost tracking | Know exactly what you're paying |
| OpenAI model pricing | Accurate cost estimates |
| Cross-platform normalization | Same analysis format as Claude Code |
| Real-time monitoring | Watch costs accumulate |
| Reasoning token tracking | See thinking tokens for o-series models (v1.3.0) |
| Built-in tool call counts | Track shell, read_file, apply_patch, etc. |

**Pain Point Addressed**: "What am I actually spending on Codex?"

**Note**: Codex CLI provides turn-level tokens only. Built-in tool call counts are tracked but per-tool token attribution is not available from the platform. Reasoning tokens (from o1, o3 models) are tracked separately from output tokens.

### Gemini CLI Users

| Feature | Benefit |
|---------|---------|
| Native session parsing | No OTEL setup required |
| Reasoning token tracking | See thinking/reasoning costs separately (v1.3.0) |
| Google model pricing | Accurate cost estimates |
| Tool call detection | Track MCP and built-in tool usage |
| Built-in tool call counts | Track read_file, list_directory, etc. |
| Optional Gemma tokenizer | 100% accurate token estimation (v0.4.0) |

**Pain Point Addressed**: "How does Gemini CLI compare to alternatives?"

**Note**: Gemini CLI provides message-level tokens only. Built-in tool call counts are tracked but per-tool token attribution is not available from the platform. Reasoning tokens (Gemini's `thoughts` field) are tracked separately from output tokens.

**Token Estimation** (v0.4.0): For 100% accurate MCP tool token estimation, run `mcp-audit tokenizer download` to get the Gemma tokenizer from GitHub Releases (no account required). Without it, mcp-audit uses tiktoken (~95% accuracy) and displays a hint during collection.

---

## mcp-audit vs ccusage

| Tool | Focus | Use Case |
|------|-------|----------|
| [ccusage](https://github.com/ryoppippi/ccusage) | Historical trends | "What did I spend this month?" |
| mcp-audit | Session tracking | "What's eating context right now?" |

ccusage is a historical analyzer—it tracks long-term usage trends (daily, monthly, all-time). mcp-audit is a **session tracker**—real-time visibility into what's happening *right now*, with per-tool granularity to investigate context bloat & high token usage as it happens.

---

## Universal Benefits

### For Everyone

| Feature | Benefit |
|---------|---------|
| **Privacy-first** | All data stays local, no prompts stored |
| **Free & open-source** | MIT license, no cost to use |
| **Lightweight install** | `pip install mcp-audit` (~500KB, optional tokenizer) |
| **Zero config needed** | Works out of the box |
| **Signal handling** | Ctrl+C saves data gracefully |
| **Multiple output formats** | JSON, CSV, Markdown reports |
| **Configurable pricing** | TOML file for custom model pricing |
| **Schema documentation** | Clear data contract for automation |
| **Theme support** | Catppuccin dark/light, high-contrast, auto-detect |
| **Accessibility** | ASCII mode, NO_COLOR standard, WCAG AAA themes |

### Privacy Guarantees

- **No prompts stored** - Only token counts and tool names
- **No network requests** - Zero telemetry, no cloud sync
- **Local storage only** - All data in `~/.mcp-audit/`
- **Redaction hooks** - Customize what gets logged

---

## Feature Comparison: Free vs What You'd Build

| Capability | Manual (grep + spreadsheets) | mcp-audit |
|------------|------------------------------|-----------|
| Real-time tracking | Not possible | Live TUI |
| Per-tool metrics | Hours of parsing | Automatic |
| Cache analysis | Complex calculation | Built-in |
| Cross-session trends | Manual aggregation | One command |
| Cost estimation | Manual lookup | Auto pricing |
| Signal handling | Data loss risk | Graceful save |

---

## Quick Reference

### Installation
```bash
pip install mcp-audit
```

### Track a Session
```bash
mcp-audit collect --platform claude-code
```

### Generate Report
```bash
mcp-audit report ~/.mcp-audit/sessions/
```

### More Information
- [README](../README.md) - Full documentation
- [Architecture](architecture.md) - System design
- [Data Contract](data-contract.md) - Schema guarantees
- [Privacy & Security](privacy-security.md) - Data handling

---

*v0.5.0 | Schema v1.5.0 | MIT License*
