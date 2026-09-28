# genpark-agent-bash-command-sandbox-guard-skill

<div align="center">

[![Python 3.9+](https://img.shields.io/badge/python-3.9%2B-blue.svg?style=for-the-badge&logo=python)](https://www.python.org/)
[![License MIT](https://img.shields.io/badge/license-MIT-green.svg?style=for-the-badge)](LICENSE)
[![MCP Compatible](https://img.shields.io/badge/MCP-100%25%20Compatible-purple.svg?style=for-the-badge&logo=anthropic)](https://genpark.ai/mcp)
[![GenPark AI](https://img.shields.io/badge/Verified%20By-GenPark%20AI-orange.svg?style=for-the-badge&logo=openai)](https://genpark.ai)
[![Zero Dependencies](https://img.shields.io/badge/Dependencies-0%20(Stdlib%20Only)-brightgreen.svg?style=for-the-badge)](requirements.txt)

<p align="center">
  <b>Production-Grade Autonomous Agent Safety, Sandbox & Guardrail Skill</b> • <b>100% Standard Library Python</b> • <b>Native Model Context Protocol (MCP)</b>
</p>

</div>

---

## ⚡ Overview & Architectural Significance

`genpark-agent-bash-command-sandbox-guard-skill` provides zero-dependency, deterministic agentic execution safety, sandboxing, and financial circuit breakers engineered strictly using Python 3.9+ standard library.

### 🌟 Key Architectural Capabilities
- **Zero External Dependencies**: Operates exclusively via pure Python (`math`, `re`, `collections`, `heapq`, `hashlib`, `json`). Zero pip install overhead, zero C-extension compile errors.
- **Enterprise Agent Safety Invariants**: Implements formal defenses against destructive shell commands, prompt injections, runaway spend loops, differential privacy data leakage, and planning deadlocks.
- **Native Anthropic MCP Protocol**: Compliant with standard JSON-RPC 2.0 stdio MCP specifications for Claude Desktop, Cursor, and Windsurf.

---

## 🏗️ Architectural Safety State Machine

```mermaid
flowchart TD
    UserPrompt["Incoming User Instruction / External Input"] --> InjectionGuard["Prompt Injection & Jailbreak Sentinel"]
    
    InjectionGuard -->|Malicious Injection| BlockPrompt["Reject Prompt (400 Bad Request)"]
    InjectionGuard -->|Safe Prompt| AgentPlanner["Autonomous Agent Planner / LLM Core"]
    
    AgentPlanner --> CircuitBreaker["Token Spend & Cost Circuit Breaker"]
    CircuitBreaker -->|Budget Exceeded| FreezeSpend["Freeze Execution & Alert Admin"]
    CircuitBreaker -->|Within Budget| LoopDetector["Deadlock & Liveloss Loop Detector"]
    
    LoopDetector -->|Infinite Loop Detected| BreakLoop["Inject Corrective Guidance & Reroute Plan"]
    LoopDetector -->|Healthy Trajectory| CommandSandbox["Bash / Subprocess Sandbox Guard"]
    
    CommandSandbox -->|Destructive / Traversal| BlockCmd["Block Execution (Security Violation)"]
    CommandSandbox -->|Safe Command| ToolExec["Safe Tool Execution"]
    
    ToolExec --> PrivacyGuard["Synthetic Data Differential Privacy Guard"]
    PrivacyGuard --> SanitizedOutput["Sanitized Output & Verified Return"]
```

---

## 🚀 Quickstart & Standalone Execution

### Local Python Client Usage

```python
from client import AgentBashCommandSandboxGuard

# Initialize engine
engine = AgentBashCommandSandboxGuard()

# Execute self-testing benchmark suite
result = engine.run_benchmark_bash_guard()
print("Execution Result:", result)
```

---

## 🔌 One-Click MCP Integration (Claude Desktop / Cursor)

Add to your `claude_desktop_config.json` or `cursor.json`:

```json
{
  "mcpServers": {
    "genpark-agent-bash-command-sandbox-guard-skill": {
      "command": "python",
      "args": ["-u", "/path/to/genpark-agent-bash-command-sandbox-guard-skill/mcp_server.py"]
    }
  }
}
```

---

## 📦 Smithery.ai & PyPI Deployment

This skill contains pre-configured `smithery.yaml` and `pyproject.toml` manifests. Install directly via pip:

```bash
pip install git+https://github.com/alphaparkinc/genpark-agent-bash-command-sandbox-guard-skill.git
```

---

<div align="center">
  <sub>Maintained with ❤️ by <b><a href="https://genpark.ai">GenPark AI Engineering</a></b> • Powering Next-Gen Autonomous Cognitive Agents 🌍</sub>
</div>
