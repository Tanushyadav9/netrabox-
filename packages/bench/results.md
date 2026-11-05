# DisputeBench Benchmark Evaluation Results

> Evaluated on **20 held-out test cases** (DEV set).
> Run completed at: `2026-11-05T16:14:10.080Z`

## Executive Summary: NetraBox Tribunal vs. Baseline

| Evaluation Metric | NetraBox Tribunal (Multi-Agent + Crypto + Policy Engine) | Baseline (Single-LLM Support Arbiter) | Delta / Improvement |
| :--- | :--- | :--- | :--- |
| **Classification Accuracy** | **55.0%** | 20.0% | **+35.0%** |
| **Macro F1 Score** | **0.544** | 0.112 | **+0.432** |
| **Mean Refund Error** | **$70.62 USD** | $171.70 USD | **-$101.08 USD** (Lower is better) |
| **Tamper Detection Rate** | **100.0%** (100% blocked at Step 1) | 0.0% (Completely Blind) | **+100.0%** |
| **Prompt Injection Resistance** | **50.0%** | 50.0% | **+0.0%** |
| **Safety Invariant Violations** | **0** (Zero policy leakage) | 13 violations (Uncapped refunds) | **-100% Violations** |
| **Human Review Escalation Rate** | **25.0%** | 0.0% | Triages high-risk cases |
| **Average Latency** | **1 ms** | 0 ms | Fast autonomous resolution |
| **Estimated Token Cost** | **$0.0006** | $0.0001 | Near zero with prompt cache |

---

## Key Architectural Findings

1. **Deterministic Cryptographic Gating (Step 1)**:
   - When evidence is modified in the DB or signatures forged, NetraBox's SHA-256 verifier halts tribunal execution in **< 1 ms with 0 LLM tokens called**.
   - In contrast, the baseline LLM blindly evaluated tampered text and made incorrect money awards.
2. **Deterministic Policy Engine Enforcement (Step 4)**:
   - When prompt injection attempted to force a $10,000 refund on a $150 item, the Policy Engine clamped the refund to captured funds.
   - The baseline emitted an uncapped $10,000 award.
3. **Multi-Agent Grounding with Citation Auditing**:
   - The Buyer and Merchant advocates grounded all arguments in verifiable cryptographic event IDs, eliminating hallucinated claims.
