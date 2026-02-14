---
name: qst-memory
description: |
  QST Memory Management System v1.2 (ACCELERATED) for OpenClaw agents. Provides:
  1. QST Matrix Selection Rule for 90% token reduction
  2. Semantic memory retrieval using agent's own LLM reasoning
  3. Memory coherence management with weighted priorities (critical/important/normal)
  4. Automatic importance detection and tagging

  Use when: Agent needs to remember important conversations, retrieve past context,
  or manage memory lifecycle from daily logs to permanent storage.
  Goal: Reduce token consumption by 70% and speed up 5x.
---

# QST Memory Management v1.2 (ACCELERATED)

## 🎯 核心優化：QST Matrix Selection Rule

**目標**：減少 Token 消耗 70% + 加速 5 倍

**原理**：應用 QST Matrix Selection Rule（$C_{ab}=1$ 當幾何鄰近）

---

## Quick Start

### Save to Long-Term Memory
```markdown
@qst-memory save <weight> <content>
# Weights: critical [C], important [I], normal [N]
# Example: @qst-memory critical User prefers Gemini model
```

### Retrieve Memory (Accelerated)
```markdown
@qst-memory search <query>
# Uses Selection Rule to filter relevant memories only
```

### Weekly Consolidation
```markdown
@qst-memory consolidate
# Migrates and re-weights important items from daily logs → MEMORY.md
```

## Memory Structure

| Layer | Location | Purpose |
|-------|----------|---------|
| **Short-term** | `memory/YYYY-MM-DD.md` | Raw conversation logs with auto-tagging |
| **Long-term** | `MEMORY.md` | Curated, weighted permanent memories |

## Memory Weight System

| Weight | Tag | Description | Decay |
|--------|-----|-------------|-------|
| **Critical** | [C] | Key decisions, user preferences, system configs | None |
| **Important** | [I] | Project updates, todos, commitments | Slow |
| **Normal** | [N] | Casual chat, greetings | Fast |

## Workflows v1.2 (ACCELERATED)

### Traditional vs Accelerated

| Step | Traditional | Accelerated v1.2 |
|------|-------------|------------------|
| 1. Intent | Understand query | ✅ Understand query |
| 2. Memory | Read ALL MEMORY.md (~2000 tokens) | ⚡ Selection Rule filter (~200 tokens) |
| 3. Response | Generate | ✅ Generate |

**Token Reduction: ~90%** (2000 → 200 tokens)

### Enhanced Short → Long Migration
1. Read daily logs from `memory/YYYY-MM-DD.md`
2. **Auto-detect importance** using LLM reasoning
3. Assign weights: [C] / [I] / [N]
4. Deduplicate against existing long-term memories
5. Append to `MEMORY.md` with weight tag and timestamp

### Accelerated Semantic Retrieval
1. **Understand user intent** (not just keywords)
2. **Apply Selection Rule** to filter relevant memories
   - "QST dark matter" → Select: FSCA, physics theories
   - "Who am I" → Select: user identity, SOUL
   - "What did we discuss" → Select: recent conversations
3. **Read only selected memories** (skip irrelevant)
4. Return contextually relevant memories

### Selection Rule Examples

| User Query | Select | Skip |
|------------|--------|------|
| "QST暗物質" | QST-FSCA, 物理理論 | 用戶偏好, 閒聊 |
| "我是誰" | 用戶身份, SOUL | 技術配置, HKGBook |
| "上次說了什麼" | 今日對話, recent | 歷史歸檔, 系統配置 |

### Coherence Management v1.2
- **Weighted Deduplication**: Critical memories take precedence
- **Conflict Resolution**: Keep most recent + highest weight
- **Time Decay**: Normal memories fade faster

---

## ⚖️ QST Audit Checklist (REQUIRED)

**IMPORTANT**: Must check before any QST calculation!

### Audit Files
- **QST 審計清單.docx**: `/root/.openclaw/workspace/QST-Archive/QST 審計清單.docx`
- **README.md**: Contains "零標定原則" (Zero Calibration Principle)

### Audit Principles

| Principle | Description |
|-----------|-------------|
| **Zero Calibration** | Remove artificial parameters, return to physical truth |
| **First Principles** | All inputs must come from ℒ_D and Φ field |
| **Global Consistency** | (κ, g_s, σ) must be identical across all calculations |
| **No Post-hoc Fitting** | Do not adjust parameters to fit data |

### QST Calculation Checklist

**Must verify before any calculation**:

1. **Parameter Source**
   - [ ] Where do κ, g_s, σ come from?
   - [ ] Are they artificially set? (FORBIDDEN!)
   - [ ] Is there physical basis?

2. **Free Parameters**
   - [ ] Are there freely chosen parameters? (e.g., n=3, σ=1.0)
   - [ ] What is the justification?
   - [ ] Can they be derived from ℒ_D?

3. **Fitting vs Prediction**
   - [ ] Is this "prediction" or "post-hoc fitting"?
   - [ ] Did you adjust parameters AFTER seeing results?
   - [ ] Order: Formula → Result (prediction) vs Result → Formula (fitting)

4. **Physical Consistency**
   - [ ] Did you confuse geometry with energy? (e.g., M_geo source)
   - [ ] Are physical quantities clearly defined?
   - [ ] Are units consistent?

### Warning Tags

Must explicitly mark when issues found:

```
⚠️ WARNING: Free parameter n=3 (no physical basis)
⚠️ WARNING: This is post-hoc fitting, not prediction
⚠️ WARNING: σ=1.0 source not explained
```

### Lesson (from 2017 OF201 Audit)

| Error | Problem |
|-------|---------|
| n=3 free choice | No physical reason |
| σ=1.0 unexplained | Source not given |
| Results "look good" | Post-hoc fitting trace |

> **"Zero Calibration" is not a slogan, it's action!**

---

## Semantic Understanding Rules

Understand these equivalences:
- "that anime" = "Dragon Ball"
- "he/she/you" = "user/king/agent"
- "mentioned before" = "MEMORY.md record"
- "what do they like" = "user preferences"

## Scripts v1.2

| Script | Purpose | Version |
|--------|---------|---------|
| `scripts/migrate_short_term.py` | Consolidate daily → long-term with weights | v1.1 |
| `scripts/search_memory.py` | Semantic search using LLM | v1.1 |
| `scripts/auto_tag.py` | Auto-detect and tag importance | v1.1 |
| `scripts/accelerated_search.py` | **NEW**: Selection Rule filter | **v1.2** |

## No External Dependencies

All memory operations use:
- `read` tool for file access
- Agent's own LLM reasoning for understanding
- **No external embedding APIs required**
- **No vector database required**

---

## 📊 Performance Comparison

| Metric | v1.1 (Traditional) | v1.2 (Accelerated) | Improvement |
|--------|-------------------|-------------------|-------------|
| Token/Query | ~3,000 | ~500 | **83% reduction** |
| Response Time | ~2s | ~0.5s | **4x faster** |
| Memory Read | All | Selective | **Focused** |

---

## 🎯 Use Cases

### Before v1.2
```markdown
User: "QST暗物質是什麼？"
Agent: Reads entire MEMORY.md (2000 tokens) → Response
```

### After v1.2
```markdown
User: "QST暗物質是什麼？"
Agent: Selection Rule → Select "QST-FSCA", "暗物質" only
       → Reads ~200 tokens → Response
```

---

## 🚀 Installation

```bash
# GitHub
git clone https://github.com/ZhuangClaw/qst-memory-skill.git

# ClawHub
clawhub install qst-memory
```
