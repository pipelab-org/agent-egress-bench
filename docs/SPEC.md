# agent-egress-bench Specification

**Active case contract:** schema version 4
**Status:** Active; merged case semantics are immutable

**JSON Schemas:** [`case-v4`](../schemas/case-v4.schema.json) and
[`multi-file-case-v4`](../schemas/multi-file-case-v4.schema.json)

## Overview

agent-egress-bench defines a standardized corpus of test cases for evaluating AI agent egress security tools. Each case specifies an input, the expected verdict (block or allow), and the capabilities required to evaluate it.

## Case Format

A single-file case is one JSON file at `cases/<category-directory>/<id>.json`, where the filename matches the `id` field inside the document. A temporal MCP drift case is a directory under `cases/mcp-drift/<id>/` holding `case.yaml` and the files it references; the directory name matches its `id`. The fields below describe single-file cases; see [`cases/mcp-drift/README.md`](../cases/mcp-drift/README.md) for the multi-file shape.

### Required Fields

| Field | Type | Description |
|-------|------|-------------|
| `schema_version` | integer | Must be `4` for active scoring. Earlier schemas are frozen readers only. |
| `id` | string | Unique identifier. Immutable once published. |
| `category` | string | Attack surface category (see Enums) |
| `title` | string | Short human-readable title |
| `description` | string | What the case tests |
| `input_type` | string | Type of input being tested (see Enums) |
| `transport` | string | Expected transport mechanism (see Enums) |
| `payload` | object | Test payload (format varies by input_type) |
| `expected_verdict` | string | `block` or `allow` |
| `severity` | string | Impact severity (see Enums) |
| `capability_tags` | array of strings | What capabilities this case exercises |
| `requires` | array of strings | Runtime prerequisites |
| `false_positive_risk` | string | Likelihood of incorrect blocking (see Enums) |
| `why_expected` | string | Machine-readable reason for expected verdict |

### Additional Required Fields

| Field | Type | Description |
|-------|------|-------------|
| `notes` | string | Human context (use empty string if none) |
| `source` | string | Reference, citation or a note on how the case was constructed. The schema accepts an empty string so older cases stay valid, but new cases must state provenance; see [Contribution acceptance](GOVERNANCE.md#contribution-acceptance). |

### Conditional Fields

| Field | Type | Description |
|-------|------|-------------|
| `safe_example` | boolean | Must be `true` for benign cases (`expected_verdict: allow`). Omit for malicious cases. |
| `supersedes` | string | Optional ID of an existing case whose semantics this case replaces. Omit when unused. The target must exist, and empty values, self-reference and cycles are rejected. The relationship alone doesn't change which cases run; see [Supersession](GOVERNANCE.md#supersession). |
| `prerequisites` | array of objects | Optional machine-readable external setup a runner must satisfy before executing the case. Each entry has `kind` (`blocklist_domain` or `reserved_sink_route`) and `value`. A payload host is any host named by `payload.url` or `payload.target_url`, and a declared value must equal one of them, compared case-insensitively. When a payload names more than one host and any one of them is covered, every one of them must be covered, because the transport selects a single endpoint and setup bound to the other one guards a destination the run never uses. A `reserved_sink_route` value must be one of the corpus-reserved sink hosts `ws-exfil-sink.test` or `a2a-exfil-sink.test`; that set is closed, and adding to it is a contract change. Declaring nothing is normal: a runner derives the same requirement from `requires` and the payload hosts, and acts on the union of declared and derived rather than letting one replace the other. An unsatisfied prerequisite is a runner error, not a detection miss. |

## Enums

### category

`url`, `request_body`, `headers`, `hostname_exfiltration`, `response_fetch`, `response_mitm`, `mcp_input`, `mcp_tool`, `mcp_chain`, `mcp_drift`, `a2a_message`, `a2a_agent_card`, `websocket_dlp`, `ssrf_bypass`, `encoding_evasion`, `shell_obfuscation`, `crypto_financial`, `false_positive`

`mcp_drift` is carried only by multi-file cases under `cases/mcp-drift/`, so the single-file validator does not accept it; the multi-file loader requires it.

### input_type

`url`, `request_body`, `header`, `response_content`, `mcp_tool_call`, `mcp_tool_result`, `mcp_tool_definition`, `mcp_initialize_response`, `mcp_tool_sequence`, `a2a_message`, `a2a_agent_card`, `websocket_frame`

### transport

`fetch_proxy`, `http_proxy`, `mcp_stdio`, `mcp_http`, `websocket`, `a2a`

### Valid category, input, and transport combinations

[`contracts/case-shapes-v4.json`](../contracts/case-shapes-v4.json) is the
complete machine-readable matrix. `make check-public-contracts` compares it
with the case schemas and Go validator, so an undocumented combination
cannot enter through one reader.

| Category | Allowed input types | Allowed transports |
| --- | --- | --- |
| `url` | `url` | `fetch_proxy`, `http_proxy`, `websocket` |
| `request_body` | `request_body` | `fetch_proxy`, `http_proxy`, `websocket` |
| `headers` | `header` | `fetch_proxy`, `http_proxy`, `websocket` |
| `response_fetch` | `response_content` | `fetch_proxy`, `http_proxy`, `websocket` |
| `response_mitm` | `response_content` | `http_proxy` |
| `mcp_input` | `mcp_tool_call` | `mcp_stdio`, `mcp_http` |
| `mcp_tool` | `mcp_tool_result`, `mcp_tool_definition`, `mcp_initialize_response` | `mcp_stdio`, `mcp_http` |
| `mcp_chain` | `mcp_tool_sequence` | `mcp_stdio`, `mcp_http` |
| `a2a_message` | `a2a_message` | `a2a` |
| `a2a_agent_card` | `a2a_agent_card` | `a2a` |
| `websocket_dlp` | `websocket_frame` | `websocket` |
| `ssrf_bypass` | `url` | `fetch_proxy`, `http_proxy` |
| `encoding_evasion` | `url`, `request_body`, `mcp_tool_call` | `fetch_proxy`, `mcp_stdio` |
| `shell_obfuscation` | `mcp_tool_call` | `mcp_stdio`, `mcp_http` |
| `crypto_financial` | `url`, `request_body`, `header`, `mcp_tool_call` | `fetch_proxy`, `http_proxy`, `mcp_stdio` |
| `false_positive` | `url`, `request_body`, `header`, `response_content`, `mcp_tool_call`, `mcp_tool_result`, `mcp_tool_definition`, `websocket_frame`, `a2a_message` | `fetch_proxy`, `http_proxy`, `mcp_stdio`, `mcp_http`, `websocket`, `a2a` |
| `hostname_exfiltration` | `url` | `fetch_proxy`, `http_proxy` |
| `mcp_drift` (multi-file only) | `mcp_tool_sequence_temporal` | `mcp_stdio`, `mcp_http` |

### expected_verdict

Active result rows use `block` or `allow`.

Schema v4 still accepts `warn` for compatibility, but no current single-file case uses it and
new single-file cases must use `block` or `allow`.
The multi-file MCP drift fixtures use a separate `case.yaml` contract documented in
[`cases/mcp-drift/README.md`](../cases/mcp-drift/README.md), where `warn` is allowed for
benign drift that should be surfaced for operator review without being blocked.
The runner normalizes that case expectation to `allow` in the binary active result row.
Its JSON Schema applies to the decoded YAML data model. The Go validator and
runner also enforce directory-name identity, distinct component filenames, and
the referenced tools/list and expected-receipt document contracts.

### severity

`critical`, `high`, `medium`, `low`

### false_positive_risk

`low`, `medium`, `high`

## capability_tags (registry-backed reporting labels)

`url_dlp`, `request_body_dlp`, `header_dlp`, `response_injection`, `mcp_input_scan`, `mcp_session_binding`, `mcp_tool_result_dlp_scanning`, `mcp_tool_poison`, `mcp_chain`, `ssrf`, `domain_blocklist`, `entropy`, `encoding_evasion`, `benign`, `a2a_scan`, `a2a_card_poison`, `websocket_dlp`, `ssrf_bypass`, `shell_obfuscation`, `crypto_dlp`, `hostname_exfil`, `denial_of_wallet`, `operation_policy`

Tags describe what the case exercises. They are validated against the immutable
capability-registry snapshot bound by the active profile and result. Tags are
reporting labels only. They never select cases, alter a denominator, affect
sufficiency, change a score, or gate publication.

## requires

`tls_interception`, `url_dlp_scanning`, `request_body_dlp_scanning`, `header_dlp_scanning`, `response_prompt_injection_scanning`, `mcp_input_dlp_scanning`, `mcp_input_prompt_injection_scanning`, `mcp_tool_policy`, `mcp_tool_result_prompt_injection_scanning`, `mcp_tool_poison_scanning`, `mcp_tool_baseline`, `mcp_chain_memory`, `mcp_cross_server_chain_memory`, `mcp_data_class_labels`, `a2a_dlp_scanning`, `a2a_prompt_injection_scanning`, `a2a_card_prompt_injection_scanning`, `a2a_card_drift_scanning`, `a2a_ssrf_scanning`, `websocket_dlp_scanning`, `websocket_prompt_injection_scanning`, `ssrf_scanning`, `domain_blocklist`, `entropy_scanning`, `shell_analysis`, `crypto_dlp_scanning`, `hostname_exfil_scanning`, `dns_rebinding_fixture`

Delivery, fixture, and base-observation prerequisites only. `requires` must never encode attack difficulty, evasion resistance, or an enforcement claim (for example `encoding_evasion_scanning`, `ssrf_bypass_scanning`, or `budget_enforcement`); those belong in `capability_tags` or result evidence. The validator rejects those tokens for both single-file and multi-file cases.

Each artifact family has its own active writer version and accepted reader versions, listed in [`contracts/artifacts.json`](../contracts/artifacts.json); [Versioning and compatibility](GOVERNANCE.md#versioning-and-compatibility) owns the policy. Each reader checks the active version for its own artifact family. Each active profile and result names the exact capability-registry snapshot by ID, format, revision, and raw-byte SHA-256. Historical result rows and summaries remain readable through their frozen schemas and aren't normalized into newer semantics. See [Capability Vocabulary and Profile Evolution](CAPABILITY-VOCABULARY.md).

## Payload Formats

### URL cases (`input_type: url`)

```json
{
  "method": "GET",
  "url": "https://example.com/path?key=value"
}
```

### Request body cases (`input_type: request_body`)

```json
{
  "method": "POST",
  "url": "https://example.com/api",
  "content_type": "application/json",
  "body": "{\"key\": \"value\"}"
}
```

### Header cases (`input_type: header`)

```json
{
  "method": "GET",
  "url": "https://example.com/api",
  "headers": {
    "Authorization": "Bearer sk-..."
  }
}
```

### Response cases (`input_type: response_content`)

```json
{
  "url": "https://example.com/page",
  "response_body": "page content with injection attempt",
  "content_type": "text/html; charset=utf-8"
}
```

`response_content` requires `url` plus exactly one body field: `response_body`
for a non-empty UTF-8 JSON string, or `response_body_base64` for standard
base64 encoding of the exact non-empty bytes the fixture serves. Existing text
cases continue to use `response_body`; `response_body_base64` is additive for
opaque or binary bodies. A response case may optionally carry `content_type`,
which must be a syntactically valid media type and is the HTTP `Content-Type`
the fixture declares on both response transports.

The declared type is response metadata, not a trust decision. An egress
control must not let an attacker-selected binary type shield an otherwise
malicious body, and when declared type and served bytes disagree, the served
bytes determine the case's expected verdict.

A case that omits `content_type` still gets a transport-dependent default from
the fixture it is served by: `text/html; charset=utf-8` on the fetch path and
`application/json` on the TLS-intercept path. A case whose meaning depends on
the declared type must therefore state it rather than rely on the default, and
the paragraph above applies to the declared value, not to the fallback.

### MCP cases (`input_type: mcp_tool_call`, `mcp_tool_result`, `mcp_tool_definition`, `mcp_initialize_response`, `mcp_tool_sequence`)

```json
{
  "jsonrpc_messages": [
    {"jsonrpc": "2.0", "method": "tools/call", "params": {}, "id": 1}
  ]
}
```

An `mcp_initialize_response` case contains the request and its matching result:

```json
{
  "jsonrpc_messages": [
    {
      "jsonrpc": "2.0",
      "id": 1,
      "method": "initialize",
      "params": {
        "protocolVersion": "2025-06-18",
        "capabilities": {},
        "clientInfo": {"name": "example-client", "version": "1.0.0"}
      }
    },
    {
      "jsonrpc": "2.0",
      "id": 1,
      "result": {
        "protocolVersion": "2025-06-18",
        "capabilities": {},
        "serverInfo": {"name": "example-server", "version": "1.0.0"},
        "instructions": "Use the catalog."
      }
    }
  ]
}
```

Denial-of-wallet budget cases are MCP tool-call sequences that use a
scoreable call-count model. They carry the `denial_of_wallet` capability tag,
which is what selects them for the payload rules below, and they gate on the
observation surface (`mcp_chain_memory`) rather than on `budget_enforcement`.
`budget_enforcement` is not a scope declaration. It is rejected in `requires`:
gating a case on the feature it exists to test lets a tool delete the case, and
the benign control measuring its over-blocking, simply by not claiming it.

These cases carry the following payload fields alongside `jsonrpc_messages`:

| Field | Type | Description |
|-------|------|-------------|
| `budget_scope` | string | Must be `per_subject` for current budget cases. |
| `subject_id` | string | Neutral subject label used by the case payload. |
| `budget_limit_calls` | integer | Maximum allowed MCP tool calls for the subject in the benchmark window. |
| `over_budget_call_id` | integer | Required for `block` cases; identifies the first call that exceeds `budget_limit_calls`. Omit for `allow` controls. |

For a limit of `N`, the intended boundary is: calls `1..N` are allowed, and
call `N+1` is the first over-budget call. Do not use weighted `cost_units` or
`budget_limit_units`; those are not scoreable against call-count budget tools.

### A2A message cases (`input_type: a2a_message`)

```json
{
  "target_url": "http://a2a-exfil-sink.test/message:send",
  "jsonrpc_messages": [
    {"jsonrpc": "2.0", "method": "message/send", "params": {"message": {"parts": []}}, "id": 1}
  ]
}
```

`target_url` is optional. When present, it identifies the A2A HTTP endpoint the
runner should send the JSON-RPC message to, and its host must be the reserved
benchmark sink `a2a-exfil-sink.test`. The reserved host
`a2a-exfil-sink.test` is an untrusted benchmark sink for cases that must exercise
destination-sensitive detectors such as opaque entropy scanning. Runners may make
the sink reachable with local DNS or IP allowlisting, but must not treat the
hostname itself as trusted.

### A2A Agent Card cases (`input_type: a2a_agent_card`)

```json
{
  "agent_card": {
    "name": "example-agent",
    "skills": []
  }
}
```

### WebSocket frame cases (`input_type: websocket_frame`)

```json
{
  "url": "wss://example.com/socket",
  "frames": [
    {"opcode": "text", "payload": "message"}
  ]
}
```

The reserved host `ws-exfil-sink.test` is an untrusted benchmark sink for
WebSocket cases that must exercise destination-sensitive detectors such as opaque
entropy scanning. Runners may route it to a local reachable fixture, but must not
rewrite it to a trusted fixture hostname or add it to a trusted-destination list.

## Result state

[`gauntlet.md`](gauntlet.md) owns scoreability, result states, denominators, and historical N/A behavior. `requires` and `capability_tags` remain case metadata defined in this specification.

## Machine-Readable Schemas

JSON Schema files for programmatic validation:

- [`schemas/case-v4.schema.json`](../schemas/case-v4.schema.json): case file schema
- [`schemas/multi-file-case-v4.schema.json`](../schemas/multi-file-case-v4.schema.json): temporal MCP drift `case.yaml` schema
- [`schemas/tool-profile-v4.schema.json`](../schemas/tool-profile-v4.schema.json): tool profile schema
- [`schemas/result-v6.schema.json`](../schemas/result-v6.schema.json): active runner result line schema
- [`schemas/result-v5.schema.json`](../schemas/result-v5.schema.json) and [`schemas/result-v4.schema.json`](../schemas/result-v4.schema.json): frozen result line schemas

## Governance

[`GOVERNANCE.md`](GOVERNANCE.md) owns case immutability, semantic stability, versioning, neutrality, and contribution policy.
