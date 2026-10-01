# Security Design Document

This document describes the security architecture of mcp-trentina-crunchtools, the MCP gateway. Deployment containment is in [docs/deployment-hardening.md](docs/deployment-hardening.md).

## 1. Threat Model

### 1.1 Assets to Protect

| Asset | Sensitivity | Impact if Compromised |
|-------|-------------|----------------------|
| Consuming agent's tool-calling capabilities | Critical | Attacker uses agent to send emails, modify files, call APIs |
| API credentials (LLM providers, OAuth, connected systems) | Critical | Data theft, unauthorized access |
| Data in connected systems | High | Exfiltration, modification, deletion |
| SQLite blocklist database | Low | Detection history exposed |

### 1.2 Threat Actors

| Actor | Capability | Motivation |
|-------|------------|------------|
| Malicious website operator | Plants injection in page content | Tool hijacking, data exfiltration |
| Compromised legitimate site | XSS injects prompt injection | Lateral movement via trusted domain |
| Malicious project contributor | Injection in README, comments, CI | Privilege escalation via code review |
| SEO poisoning | Injection in search results | Agent manipulation |

### 1.3 Attack Vectors

| Vector | Description | Mitigation |
|--------|-------------|------------|
| **Hidden HTML injection** | display:none, off-screen, same-color text | The `html` pre-processor converts markup to Markdown, which cannot express hidden text; L1 counts what it finds |
| **Invisible unicode** | Zero-width chars, bidi overrides | L1 counts them in attack context and strips them from L2's copy |
| **Encoded payloads** | Base64/hex instruction injection | L1 detects; L2 and L3 judge |
| **Exfiltration URLs** | Markdown images with data in query params | L1 detects; the egress guard refuses non-global addresses |
| **LLM delimiter spoofing** | Fake im_start, INST, Human: | L1 detects known delimiters |
| **Instruction override** | "Ignore previous instructions" and kin | L2 (Prompt Guard 2) |
| **Semantic injection** | Instructions disguised as text, social engineering | L3 quarantined LLM, best effort |
| **LLM laundering** | P-LLM rephrases quarantined content | Not defended (requires CaMeL $VAR tokens) |

## 2. Security Architecture

### 2.1 Defense in Depth Layers

Every untrusted payload, at every ingress (web, tool responses, tool
descriptions, Matrix, LLM completions, alerts), runs all three layers. None
can be switched off; an absent layer is a gap that `block` and `redact` refuse
on. Details and measured catch rates: [docs/defense-pipeline.md](docs/defense-pipeline.md).

```
+---------------------------------------------------------+
| Layer 1: Deterministic checks (l1/)                      |
| - Hidden-content, invisible Unicode, encoded payload,    |
|   exfiltration URL and delimiter counts                  |
| - Exact directive patterns, plus evasion undoing         |
| - Normalizes a COPY for L2; never modifies delivery      |
+---------------------------------------------------------+
| Layer 2: Prompt Guard 2 86M classifier (local ONNX)      |
| - Reads the original and, when L1 changed it, the copy   |
+---------------------------------------------------------+
| Layer 3: Quarantined LLM, briefed with L1 and L2         |
| - NO tools, NO SDK, NO memory                            |
| - Answers held to a response schema; off-schema is a gap |
| - Finding types are a closed enum: no L3 prose reaches   |
|   an agent                                               |
+---------------------------------------------------------+
| Cumulative memory: SQLite blocklist                      |
| - Written by deterministic code only                     |
| - A refused source stays refused for its TTL             |
+---------------------------------------------------------+
| Trust allowlist: operator configuration                  |
| - Not agent-controlled                                   |
| - Turns a `block` refusal into `redact`; all three       |
|   layers still run                                       |
+---------------------------------------------------------+
```

Around the layers: the egress guard (`egress.py`) pins every gateway-side
fetch to a resolved, global address; file reads are confined
(`tools/confine.py`); parameter and response guards hold tool calls to
operator policy; `posture.py` checks the container's own containment.

### 2.2 L3 Architectural Quarantine

The quarantined LLM's security comes from architectural constraints, not prompt engineering:

1. **No tools**: no provider's request body is built with tool declarations. The Gemini path also refuses one at runtime (`_enforce_quarantine`).
2. **No SDK**: raw httpx REST calls, so no SDK can configure a tool by accident.
3. **No memory**: each request is stateless.
4. **No write access**: its answer is parsed and schema-checked by deterministic code (`quarantine/schema.py`). It cannot write to the blocklist or any other state, and none of its text is delivered to an agent.

### 2.3 Input Validation

All inputs are validated through Pydantic models:

- **URLs**: Must be valid HTTP/HTTPS
- **File paths**: No path traversal (..), text files only, size limited
- **Prompts**: String inputs (no injection risk to server itself)
- **Extra fields**: Rejected (Pydantic extra="forbid")

## 3. Supply Chain Security

### 3.1 Container Security

Built on **[Hummingbird Python](https://quay.io/repository/hummingbird/python)** for minimal CVE exposure.

### 3.2 Dependency Minimization

No LLM provider SDKs. Direct REST calls via httpx eliminate their dependency trees.

## 4. Security Checklist

Before each release:

- [ ] All inputs validated through Pydantic models
- [ ] L3 request body verified: no tools, no functionDeclarations
- [ ] No shell execution
- [ ] No eval/exec
- [ ] Error messages scrub API keys (SecretStr)
- [ ] Dependencies scanned for CVEs
- [ ] Container rebuilt with latest Hummingbird base
- [ ] Gourmand passes (defensive_error_silencing check)

## 5. Reporting Security Issues

Report security vulnerabilities using [GitHub's private security advisory](https://github.com/crunchtools/mcp-trentina/security/advisories/new).

Do NOT open public issues for security vulnerabilities.
