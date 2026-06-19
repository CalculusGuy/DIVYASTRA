██████╗ ██╗██╗   ██╗██╗   ██╗ █████╗ ███████╗████████╗██████╗  █████╗
██╔══██╗██║██║   ██║╚██╗ ██╔╝██╔══██╗██╔════╝╚══██╔══╝██╔══██╗██╔══██╗
██║  ██║██║██║   ██║ ╚████╔╝ ███████║███████╗   ██║   ██████╔╝███████║
██║  ██║██║╚██╗ ██╔╝  ╚██╔╝  ██╔══██║╚════██║   ██║   ██╔══██╗██╔══██║
██████╔╝██║ ╚████╔╝    ██║   ██║  ██║███████║   ██║   ██║  ██║██║  ██║
╚═════╝ ╚═╝  ╚═══╝     ╚═╝   ╚═╝  ╚═╝╚══════╝   ╚═╝   ╚═╝  ╚═╝╚═╝  ╚═╝


# AI Security Testing Framework for Prompt Injection & Jailbreak Detection


A pluggable command-line tool for testing LLM-integrated applications
against a structured library of known prompt injection attack patterns.

Built after completing PortSwigger Web Security Academy's full Web LLM
Attacks module (8/8, Apprentice → Expert). This tool automates the
detection patterns learned there instead of relying on manual testing.

## Why this exists

Most prompt injection "testing" is manual — someone pastes a jailbreak
into a chat box and eyeballs the response. That doesn't scale and isn't
repeatable. PI Tester treats prompt injection testing like any other
security scanning discipline: a payload library, a target abstraction,
automated scoring, and a structured report.

## Features

- **Pluggable targets** — built-in adapters for Ollama (local), any
  OpenAI-compatible API, and arbitrary custom HTTP endpoints. Add a new
  target by implementing one method (`send()`).
- **Categorized payload library** — instruction override, role-play
  jailbreaks, exfiltration attempts, indirect injection, encoding
  obfuscation, and scope boundary tests.
- **Heuristic detection engine** — scores each response on success
  signals, refusal language, and compliance language to produce a
  confidence-rated verdict (`vulnerable` / `uncertain` / `likely_safe`).
- **Dual output** — readable color-coded CLI report, plus structured
  JSON for future dashboards or CI pipelines.

## Installation

```bash
git clone https://github.com/CalculusGuy/pi-tester.git
cd pi-tester
pip install -r requirements.txt
```

## Usage

Test a local Ollama model:

```bash
python pi_tester.py --target ollama --model llama3
```

Test an OpenAI-compatible API:

```bash
python pi_tester.py --target openai --api-key sk-... --model gpt-4o-mini
```

Test a custom chatbot endpoint:

```bash
python pi_tester.py --target custom --url https://example.com/api/chat
```

Run only one category, save a JSON report:

```bash
python pi_tester.py --target ollama --category role_play_jailbreak --json-out reports/run1.json
```

Run a single payload by ID:

```bash
python pi_tester.py --target ollama --payload-id io_001
```

## Architecture

```
pi-tester/
├── pi_tester.py          # CLI entry point
├── payloads/
│   └── payloads.yaml     # Categorized injection payload library
├── adapters/
│   ├── base_adapter.py   # Abstract interface — implement this for new targets
│   ├── ollama_adapter.py
│   ├── openai_style_adapter.py
│   └── custom_http_adapter.py
├── core/
│   ├── engine.py         # Orchestrates payload → adapter → detector
│   ├── detector.py       # Heuristic scoring logic
│   ├── cli_report.py     # Terminal output formatting
│   └── json_report.py    # JSON report writer
└── reports/               # Generated JSON reports land here
```

## Adding a new target

Implement `BaseAdapter`:

```python
from adapters.base_adapter import BaseAdapter

class MyTargetAdapter(BaseAdapter):
    name = "my_target"

    def send(self, prompt: str) -> str:
        # call your target, return its text response
        ...
```

## Adding new payloads

Edit `payloads/payloads.yaml`. Each payload needs an `id`, `text`, and
an optional `success_signal` — a string the detector looks for in the
response to flag a successful injection.

## Detection methodology

This is a heuristic engine, not an ML classifier — by design. Every
verdict is traceable to specific, inspectable rules:

1. Does the response contain the payload's expected success signal?
2. Does the response contain refusal language?
3. Does the response contain compliance-style language without refusal?

Confidence scores combine these signals. `vulnerable` (≥0.6),
`likely_safe` (≤0.15), `uncertain` (in between — recommend manual review).

## Disclaimer

For authorized security testing only. Only run this against systems you
own or have explicit permission to test.

## Author

Nilanjan Chowdhury ([CalculusGuy](https://github.com/CalculusGuy))
1st-year BCA Cybersecurity, RCC Institute of Information Technology, Kolkata
