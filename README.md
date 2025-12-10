# MCP Audit &nbsp; [![PyPI version](https://img.shields.io/pypi/v/mcp-audit?style=for-the-badge&logo=pypi&logoColor=white)](https://pypi.org/project/mcp-audit/) ![Project Status](https://img.shields.io/badge/Status-Active-brightgreen?style=for-the-badge)

**mcp-audit is a real-time token profiler for MCP servers and MCP tools.**

It helps you diagnose **context bloat**, **auto-compaction**, and **unexpected token spikes** across **Claude Code**, **Codex CLI**, and **Gemini CLI**—so you always know which MCP tool or MCP server is consuming your tokens and why.

![MCP Audit real-time TUI showing token usage](https://raw.githubusercontent.com/littlebearapps/mcp-audit/main/docs/images/demo.gif)
> *Real-time token tracking & MCP tool profiling — understand exactly where your tokens go.*

[![Downloads](https://img.shields.io/pepy/dt/mcp-audit?style=for-the-badge&logo=pypi&logoColor=white)](https://pepy.tech/project/mcp-audit)
[![CI](https://img.shields.io/github/actions/workflow/status/littlebearapps/mcp-audit/ci.yml?branch=main&label=CI&style=for-the-badge&logo=github&logoColor=white)](https://github.com/littlebearapps/mcp-audit/actions/workflows/ci.yml)
[![License: MIT](https://img.shields.io/badge/License-MIT-yellow?style=for-the-badge)](https://opensource.org/licenses/MIT)

---

## ⚡ Quick Install

```bash
pipx install mcp-audit
```

<details>
<summary>Alternative: pip or uv</summary>

```bash
pip install mcp-audit
```

```bash
uv pip install mcp-audit
```

</details>

<details>
<summary>Upgrade to latest version</summary>

```bash
# pipx
pipx upgrade mcp-audit

# pip
pip install --upgrade mcp-audit

# uv
uv pip install --upgrade mcp-audit
```

</details>

**💡 Gemini CLI Users:** For 100% accurate token counts (instead of ~95%), run `mcp-audit tokenizer download` after installing.

```bash
mcp-audit tokenizer download
```

---

## 🖥️ Compatibility

**Python:**

[![Python Versions](https://img.shields.io/pypi/pyversions/mcp-audit?style=for-the-badge&logo=python&logoColor=white)](https://pypi.org/project/mcp-audit/)

**Operating Systems:**
- **macOS** – fully supported
- **Linux** – works, CI coverage coming soon
- **Windows** – recommended via **WSL** (native PowerShell support not yet guaranteed)

---

## 👥 Who Is This For?

| 🛠️ **The Builder** | 💻 **The Vibecoder** |
|:---|:---|
| *"Is my MCP server (or the one I downloaded) too heavy?"* | *"Why did my CLI Agent auto-compact so quickly?"* |
| You build MCP servers and want visibility into token consumption patterns. | You use Cursor/Claude daily and hit context limits without knowing why. |
| **You need:** Per-tool token breakdown, usage trends. | **You need:** Real-time cost tracking, session telemetry. |

---

## 🚀 What mcp-audit Does (At a Glance)

A real-time MCP token profiler designed to help you understand exactly where your tokens are going — and why.

### 🔎 Token Profiling
- Tracks real-time token usage across Claude Code, Codex CLI, and Gemini CLI
- Breaks down usage by server, tool, and individual call

### 🧠 Problem Detection
- Flags context bloat and schema overhead ("context tax")
- Detects early auto-compaction triggers
- Highlights payload spikes and chatty tools

### 📊 Analysis & Reporting
- Generates post-session summaries for deeper optimisation
- Supports multi-session comparisons (aggregation mode)

### 🔒 Privacy & Integration &nbsp; ![Data Stays Local](https://img.shields.io/badge/Data-Stays%20Local-blue?style=for-the-badge)

- No proxies, no interception, no cloud uploads — all data stays local
- Works alongside existing agent workflows with zero setup overhead

---

## ❓ MCP Problems mcp-audit Helps Solve

**"Why is my MCP server using so many tokens?"**

Large `list_tools` schemas and verbose tool outputs add a hidden context tax.
mcp-audit reveals exactly where that cost comes from.

**"Why does Claude Code keep auto-compacting?"**

Auto-compaction usually triggers when tool schemas or outputs are too large.
mcp-audit shows the exact schema + tool calls contributing to early compaction.

**"Which MCP tools are the most expensive?"**

The TUI highlights per-tool token usage, spikes, and trends in real time.

**"How do I reduce token costs in multi-step agent workflows?"**

Use the post-session reports to identify inefficient tool patterns, chatty tools, and large payloads.

---

### 🛡️ How It Works (Safe & Passive)

`mcp-audit` is a **passive observer**. It watches your local session logs and artifacts in real-time.
* **No Proxies:** It does not intercept your network traffic or API calls.
* **No Latency:** It runs as a sidecar process, adding zero overhead to your agent.
* **Local Only & Private:** All data remains on your machine.
* **Telemetry Only:** Provides signals and metrics — you (or your AI) decide what to do with them.

**Note:** MCP Audit is telemetry-only — no recommendations or optimizations are performed automatically.
Use the AI export (coming in v0.5.0) to analyze your results with your preferred AI CLI.

mcp-audit helps you understand *why* your MCP tools behave the way they do—whether it's high token usage, slow agent performance, or unexpected context growth.
It turns raw MCP telemetry into actionable insights you can use to optimise your agent workflows.

---

## 🚀 What's New &nbsp; [![Latest Release](https://img.shields.io/github/v/release/littlebearapps/mcp-audit?style=for-the-badge&logo=github&logoColor=white)](https://github.com/littlebearapps/mcp-audit/releases/latest)

- **High-Accuracy Token Estimation:** Session-level tokens are **99-100% accurate** for Codex CLI and Gemini CLI (using tiktoken/Gemma tokenizers). Per-tool estimates are also highly accurate.
- **Theme Support:** Full theme support including **Catppuccin Mocha/Latte** and High Contrast modes.
- **Ultra Light:** Core package size reduced from 5MB to **<500KB** (~2.5MB with optional Gemma tokenizer).

See the [Changelog](https://github.com/littlebearapps/mcp-audit/blob/main/CHANGELOG.md) for full version history.

---

## 🔍 What to Look For (The "Audit")

Once you're running `mcp-audit`, watch for these common patterns in your telemetry:

1. **The "Context Tax" (High Initial Load):**
   - *Signal:* Your session starts with 10k+ tokens before you type a word.
   - *What this might indicate:* Large `list_tools` schemas can increase context usage on each turn (detailed telemetry coming in v0.6.0+).

2. **The "Payload Spike" (Unexpected Cost):**
   - *Signal:* A single tool call consumes far more tokens than expected.
   - *What this might indicate:* Large file reads or verbose API responses.

3. **The "Zombie Tool":** *(detection coming in v0.5.0)*
   - *Signal:* A tool appears in your schema but is never called.
   - *What this might indicate:* Unused tools consuming schema tokens on every turn.

4. **The "Auto-Compaction Trigger"** (Early Context Collapse):
   - *Signal:* Claude Code or Codex CLI compacts the conversation unexpectedly early.
   - *What this might indicate:* High schema weight or repeated inclusion of large payloads.
   - *How mcp-audit helps:* Identifies which MCP server or MCP tool is pushing the session over the threshold.

---

## 🎮 Quick Start

### 1. Start Tracking

Open a separate terminal window and run (see [Platform Guides](#-documentation) for detailed setup):

```bash
# Auto-detects your platform (or specify with --platform)
mcp-audit collect --platform claude-code
mcp-audit collect --platform codex-cli
mcp-audit collect --platform gemini-cli
```

### 2. Work Normally

Go back to your agent (Claude Code, Codex CLI, or Gemini CLI) and start working. The MCP Audit TUI updates in real-time as you use tools.

> **TUI runs automatically.** Other display options: `--quiet` (logs only), `--plain` (CI/pipelines), `--no-logs` (display only).

### 3. Analyze Later

Generate a post-mortem report to see where the money went:

```bash
# See the top 10 most expensive tools
mcp-audit report ~/.mcp-audit/sessions/ --top-n 10

# Session logs are stored by default in ~/.mcp-audit/sessions/
```

Now that you're collecting telemetry, read [What to Look For](#-what-to-look-for-the-audit) to understand the signals that indicate context bloat, expensive tools, and auto-compaction risks.

---

## 🤖 Supported Agents

![Claude Code](https://img.shields.io/badge/Claude%20Code-D97757?style=for-the-badge&logo=anthropic&logoColor=white)
![OpenAI Codex](https://img.shields.io/badge/Codex%20CLI-412991?style=for-the-badge&logo=openai&logoColor=white)
![Google Gemini](https://img.shields.io/badge/Gemini%20CLI-8E75B2?style=for-the-badge&logo=google%20gemini&logoColor=white)

| Platform | Token Accuracy | Tracking Depth | Notes |
| :--- | :--- | :--- | :--- |
| **Claude Code** | **Native** (100%) | Full (Per-Tool) | Shows exact server-side usage. |
| **Codex CLI** | **Estimated** (99%+) | Session + Tool | Uses `o200k_base` tokenizer for near-perfect precision. |
| **Gemini CLI** | **Estimated** (100%) | Session + Tool | Uses `Gemma` tokenizer (requires download) or fallback (~95%). |
| **Ollama CLI** | — | — | Coming soon. |

- Session-level token accuracy is 99–100% for Codex CLI and Gemini CLI.  
  *(Per-tool token counts are estimated and highly accurate in most cases.)*

> **Want support for another CLI platform?** [Start a discussion](https://github.com/littlebearapps/mcp-audit/discussions/new?category=ideas) and let us know what you need!

---

## 🧠 Why Developers Use mcp-audit

MCP tools and servers often generate hidden token overhead—from schema size, payload spikes, and inefficient tool patterns.
These issues cause:

- **Early auto-compaction** — sessions end prematurely
- **Slow agent performance** — large contexts increase latency
- **Unexpected cost increases** — tokens add up faster than expected
- **Misleading debug logs** — hard to trace the real source of bloat
- **Context window exhaustion** — hitting limits before finishing work

mcp-audit exposes these hidden costs and helps you build faster, cheaper, more predictable MCP workflows.

---

<details>
<summary><strong>Detailed Platform Capabilities</strong></summary>
<br>

| Capability | Claude Code | Codex CLI | Gemini CLI |
|------------|:-----------:|:---------:|:----------:|
| Session tokens | ✅ Full | ✅ Full | ✅ Full |
| Per-tool tokens | ✅ Native | ✅ Estimated | ✅ Estimated |
| Reasoning tokens | ❌ Not exposed | ✅ o-series | ✅ Gemini 2.0+ |
| Cache tracking | ✅ Create + Read | ✅ Read only | ✅ Read only |
| Cost estimates | ✅ Accurate | ✅ Accurate | ✅ Accurate |

</details>

---

## 🤝 The Token Ecosystem (When to use what)

`mcp-audit` focuses on **real-time MCP inspection**. It fits perfectly alongside other tools in your stack:

| Tool | Best For... | The Question it Answers |
| :--- | :--- | :--- |
| **MCP Audit** (Us) | ⚡ **Deep Profiling** | "Which specific tool is eating my tokens right now?" |
| **[ccusage](https://github.com/ryoppippi/ccusage)** | 📅 **Billing & History** | "How much did I spend last month?" |
| **[Claude Code Usage Monitor](https://github.com/Maciek-roboblog/Claude-Code-Usage-Monitor)** | 🛑 **Session Limits** | "Will I hit my limit in the next hour?" |

---

## ⚙️ Configuration & Theming

**New in v0.4.0:** Customize your dashboard look!

```bash
# Use the Catppuccin Mocha theme
mcp-audit collect --theme mocha

# Use Catppuccin Latte (light)
mcp-audit collect --theme latte

# Use High Contrast (Accessibility - WCAG AAA)
mcp-audit collect --theme hc-dark
```

*Supported Themes:* `auto`, `dark`, `light`, `mocha`, `latte`, `hc-dark`, `hc-light`

> **Note:** Advanced features such as smell detection, zombie tool detection,  
> AI prompt export, and multi-model sessions are part of the upcoming v0.5.0+ releases.

### Pricing Configuration

Customize model pricing in `mcp-audit.toml`:

```toml
[pricing.claude]
"claude-opus-4-5-20251101" = { input = 5.00, output = 25.00 }

[pricing.openai]
"gpt-5.1" = { input = 1.25, output = 10.00 }
```

Prices in USD per million tokens. See [Pricing Configuration](https://github.com/littlebearapps/mcp-audit/blob/main/docs/PRICING-CONFIGURATION.md) for all models.

---

## 💻 CLI Reference

```bash
# Most common usage - just run this and start working
mcp-audit collect

# Specify your platform explicitly
mcp-audit collect --platform claude-code
mcp-audit collect --platform codex-cli
mcp-audit collect --platform gemini-cli

# Use a dark theme (try: mocha, latte, hc-dark, hc-light)
mcp-audit collect --theme mocha

# See where your tokens went after a session
mcp-audit report ~/.mcp-audit/sessions/

# Gemini CLI users: download tokenizer for 100% accuracy
mcp-audit tokenizer download
```

### collect

Track a live session.

```
Options:
  --platform          Platform: claude-code, codex-cli, gemini-cli, auto
  --project TEXT      Project name (auto-detected from directory)
  --theme NAME        Color theme (default: auto)
  --pin-server NAME   Pin server(s) at top of MCP section
  --from-start        Include existing session data (Codex/Gemini only)
  --quiet             Suppress display output (logs only)
  --plain             Plain text output (for CI/logs)
  --no-logs           Skip writing logs to disk (real-time display only)
```

### report

Generate usage report.

```
Options:
  --format           Output: json, csv, markdown (default: markdown)
  --output PATH      Output file (default: stdout)
  --aggregate        Aggregate across multiple sessions
  --top-n INT        Number of top tools to show (default: 10)
```

### tokenizer

Manage optional tokenizers.

```bash
mcp-audit tokenizer download   # Download Gemma tokenizer (~4MB)
mcp-audit tokenizer status     # Check tokenizer availability
```

### Upgrade

```bash
# pipx (recommended)
pipx upgrade mcp-audit

# pip
pip install --upgrade mcp-audit

# uv
uv pip install --upgrade mcp-audit
```

### Uninstall

```bash
# If installed with pipx
pipx uninstall mcp-audit

# If installed with pip
pip uninstall mcp-audit
```

---

## ❓ Usage & Support FAQ

<details open>
<summary><strong>How accurate is token estimation for Codex CLI and Gemini CLI?</strong></summary>

<br>

**Very accurate.** In v0.4.0, we use the same tokenizers as the underlying models:

- **Codex CLI (OpenAI):** Uses `tiktoken` with the `o200k_base` encoding — the same tokenizer OpenAI uses. Session-level accuracy is **99%+**.
- **Gemini CLI (Google):** Uses the official `Gemma` tokenizer (via `mcp-audit tokenizer download`). Session-level accuracy is **100%**. Without it, we fall back to `tiktoken` at ~95% accuracy.

**Per-tool token estimates** are also highly accurate in most cases, though platforms don't provide native per-tool attribution (only Claude Code does).

Claude Code provides native token counts directly from Anthropic's servers, so no estimation is needed there.

</details>

<details>
<summary><strong>Why am I seeing 0 tokens or no activity?</strong></summary>

<br>

1. **Started mcp-audit after the agent** — Only new activity is tracked. Start `mcp-audit` first, then your agent.
2. **Wrong directory** — mcp-audit looks for session files based on your current working directory.
3. **No MCP tools used yet** — Built-in tools (Read, Write, Bash) are tracked separately. Try using an MCP tool.

</details>

<details>
<summary><strong>Where is my data stored?</strong></summary>

<br>

**All data stays on your machine:**
- Session data: `~/.mcp-audit/sessions/`
- Configuration: `~/.mcp-audit/mcp-audit.toml`
- No network requests, no telemetry

Only token counts and tool names are logged—**prompts and responses are never stored**.

</details>

<details>
<summary><strong>Can mcp-audit help diagnose context bloat in MCP servers?</strong></summary>

<br>

Yes. mcp-audit tracks schema weight, per-tool usage, and payload spikes that contribute to context bloat in Claude Code, Codex CLI, and Gemini CLI. It helps you understand why your agent is using so many tokens and where optimisation will have the biggest impact.

</details>

---

## 📚 Documentation

### 🚀 Getting Started Guides

| Platform | Guide |
|----------|-------|
| **Claude Code** | [Setup & Troubleshooting](https://github.com/littlebearapps/mcp-audit/blob/main/docs/platforms/claude-code.md) |
| **Codex CLI** | [Setup & Troubleshooting](https://github.com/littlebearapps/mcp-audit/blob/main/docs/platforms/codex-cli.md) |
| **Gemini CLI** | [Setup & Troubleshooting](https://github.com/littlebearapps/mcp-audit/blob/main/docs/platforms/gemini-cli.md) |

### 📖 Reference

| Document | Description |
|----------|-------------|
| [Features & Benefits](https://github.com/littlebearapps/mcp-audit/blob/main/docs/FEATURES-BENEFITS.md) | Detailed feature guide |
| [Architecture](https://github.com/littlebearapps/mcp-audit/blob/main/docs/architecture.md) | System design and adapters |
| [Data Contract](https://github.com/littlebearapps/mcp-audit/blob/main/docs/data-contract.md) | Schema v1.4.0 format |
| [Privacy & Security](https://github.com/littlebearapps/mcp-audit/blob/main/docs/privacy-security.md) | Data handling policies |
| [Manual Tokenizer Install](https://github.com/littlebearapps/mcp-audit/blob/main/docs/manual-tokenizer-install.md) | For firewalled networks |
| [Changelog](https://github.com/littlebearapps/mcp-audit/blob/main/CHANGELOG.md) | Version history |
| [Roadmap](https://github.com/littlebearapps/mcp-audit/blob/main/ROADMAP.md) | Planned features |

---

## 🗺️ Roadmap

**Current**: v0.4.x — Stable for daily use

**Coming in v0.5.0:**
- Smell detection signals — identify inefficient or unstable MCP tools (HIGH_VARIANCE, TOP_CONSUMER, CHATTY)
- AI-friendly session export — let your AI analyse usage patterns
- Zombie tool detection — find unused tools increasing schema cost

**Coming in v0.6.0+:**
- Multi-model session tracking — compare token behaviour across agents
- TUI session browser — explore past sessions visually
- Static/dynamic payload metrics — measure schema vs output cost
- Ollama CLI support — expand tool ecosystem

See the full [Roadmap](https://github.com/littlebearapps/mcp-audit/blob/main/ROADMAP.md) for details.

**Have an idea or feature request?** [Start a discussion](https://github.com/littlebearapps/mcp-audit/discussions/new?category=ideas)

---

## 🤝 Contributing

We welcome contributions! See [CONTRIBUTING.md](https://github.com/littlebearapps/mcp-audit/blob/main/CONTRIBUTING.md) for guidelines.

- **Bug reports**: [Open an Issue](https://github.com/littlebearapps/mcp-audit/issues/new?template=bug_report.md)
- **Feature ideas**: [Start a Discussion](https://github.com/littlebearapps/mcp-audit/discussions/new?category=ideas)
- **Questions**: [Ask in Discussions](https://github.com/littlebearapps/mcp-audit/discussions/new?category=q-a)

### Development Setup

```bash
git clone https://github.com/littlebearapps/mcp-audit.git
cd mcp-audit
pip install -e ".[dev]"
pytest
```

---

## 📄 License

MIT License — see [LICENSE](https://github.com/littlebearapps/mcp-audit/blob/main/LICENSE) for details.

**Third-Party:**
- [tiktoken](https://github.com/openai/tiktoken) (MIT) — Bundled for Codex CLI token estimation
- [Gemma tokenizer](https://huggingface.co/google/gemma-2-2b) (Apache 2.0) — Optional download for Gemini CLI. See [Gemma Tokenizer License](https://github.com/littlebearapps/mcp-audit/blob/main/docs/gemma-tokenizer-license.md) for terms.

---

**Made with 🐻 by [Little Bear Apps](https://littlebearapps.com)**

[Issues](https://github.com/littlebearapps/mcp-audit/issues) · [Discussions](https://github.com/littlebearapps/mcp-audit/discussions) · [Roadmap](https://github.com/littlebearapps/mcp-audit/blob/main/ROADMAP.md)
