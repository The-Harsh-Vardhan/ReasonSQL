---
title: v1 pipeline design
---

> **Historical document.** This describes the v1 12-agent, 4-batch orchestrator. ReasonSQL 2.0 replaced it with a LangGraph `StateGraph` of 7 nodes; see [Architecture](architecture) for the current pipeline.

# 🔄 NL2SQL Agent Pipeline - Detailed Flow

> **Complete visualization of how 12 specialized agents collaborate to convert natural language to SQL**

---

## 📊 Executive Summary

**Pipeline Architecture:** 4 Batches → 12 Agents → 4 LLM Calls  
**Execution Time:** 2-5 seconds (depending on complexity and retries)  
**Success Rate:** 85%+ on complex queries

---

## 🎯 Pipeline Overview

```
┌─────────────────────────────────────────────────────────────────────┐
│                         USER QUERY                                   │
│              "Show me the top 5 artists by track count"             │
└─────────────────────────────────────────────────────────────────────┘
                              │
                              ▼
╔═════════════════════════════════════════════════════════════════════╗
║                    BATCH 1: INTENT ANALYSIS                         ║
║                        (1 LLM Call)                                 ║
╚═════════════════════════════════════════════════════════════════════╝
                              │
              ┌───────────────┼───────────────┐
              ▼               ▼               ▼
        DATA_QUERY      META_QUERY      AMBIGUOUS
              │               │               │
              │               ▼               ▼
              │      [Schema Explorer]   [Clarification]
              │               │               │
              │               ▼               ▼
              │       Return Schema    Ask User Question
              │           [END]             [END]
              │
              ▼
╔═════════════════════════════════════════════════════════════════════╗
║              BATCH 2: SCHEMA EXPLORATION & PLANNING                 ║
║                        (1 LLM Call)                                 ║
╚═════════════════════════════════════════════════════════════════════╝
              │
              ▼
╔═════════════════════════════════════════════════════════════════════╗
║              BATCH 3: SQL GENERATION & SAFETY CHECK                 ║
║                        (1 LLM Call)                                 ║
╚═════════════════════════════════════════════════════════════════════╝
              │
              ▼
       [Safety Validator]
              │
      ┌───────┴───────┐
      ▼               ▼
  APPROVED         BLOCKED
      │               │
      ▼               ▼
 [Execute SQL]    Return Error
      │             [END]
      │
  ┌───┴────┐
  ▼        ▼
SUCCESS  FAILURE
  │        │
  │        ▼
  │   [Self-Correction]
  │        │
  │        └──> Retry (max 3x)
  │
  ▼
╔═════════════════════════════════════════════════════════════════════╗
║                 BATCH 4: RESPONSE SYNTHESIS                         ║
║                        (1 LLM Call)                                 ║
╚═════════════════════════════════════════════════════════════════════╝
              │
              ▼
┌─────────────────────────────────────────────────────────────────────┐
│                      FINAL RESPONSE                                  │
│  • Human-readable answer                                            │
│  • SQL query used                                                   │
│  • Data preview                                                     │
│  • Full reasoning trace                                             │
└─────────────────────────────────────────────────────────────────────┘
```

---

## 🔍 Detailed Agent Pipeline

### **BATCH 1: Intent Analysis & Clarification**
**LLM Calls:** 1 | **Duration:** ~500ms

```
┌─────────────────────────────────────────────────────────────────┐
│  Agent #1: IntentAnalyzer                                       │
│  ─────────────────────────────────────────────────────────────  │
│  Input:  User query                                             │
│  Output: Classification (DATA_QUERY, META_QUERY, AMBIGUOUS)     │
│  Logic:  LLM-based intent classification                        │
│  Example:                                                        │
│    "Top 5 artists" → DATA_QUERY                                 │
│    "What tables exist?" → META_QUERY                            │
│    "Show recent orders" → AMBIGUOUS (what is 'recent'?)        │
└─────────────────────────────────────────────────────────────────┘
                            │
                            ▼
┌─────────────────────────────────────────────────────────────────┐
│  Agent #2: ClarificationAgent (only if AMBIGUOUS)               │
│  ─────────────────────────────────────────────────────────────  │
│  Input:  Ambiguous query + context                              │
│  Output: Clarifying question OR resolved query                  │
│  Logic:  Detects vague terms (recent, best, top, etc.)         │
│  Example:                                                        │
│    "Show recent orders"                                         │
│    → "How recent? Last week, month, or year?"                  │
│    [PIPELINE STOPS - Wait for user response]                   │
└─────────────────────────────────────────────────────────────────┘
                            │
                            ▼
            ┌───────────────┴───────────────┐
            │                               │
    If DATA_QUERY                    If META_QUERY
            │                               │
            ▼                               ▼
      Continue to                   ┌─────────────────┐
      Batch 2                       │ SchemaExplorer  │
                                   │ Returns schema  │
                                   └─────────────────┘
                                           │
                                           ▼
                                      [END - No SQL needed]
```

---

### **BATCH 2: Schema Exploration & Query Planning**
**LLM Calls:** 1 | **Duration:** ~800ms

```
┌─────────────────────────────────────────────────────────────────┐
│  Agent #3: SchemaExplorer (Rule-based)                          │
│  ─────────────────────────────────────────────────────────────  │
│  Input:  Database connection                                    │
│  Output: Schema (tables, columns, types, relationships)         │
│  Logic:  SQLite metadata queries                                │
│  Example Output:                                                 │
│    Tables: Artist, Album, Track                                 │
│    Artist.ArtistId → Album.ArtistId (FK)                        │
│    Album.AlbumId → Track.AlbumId (FK)                           │
└─────────────────────────────────────────────────────────────────┘
                            │
                            ▼
┌─────────────────────────────────────────────────────────────────┐
│  Agent #4: QueryDecomposer                                      │
│  ─────────────────────────────────────────────────────────────  │
│  Input:  User query + schema                                    │
│  Output: Query breakdown (sub-tasks, tables needed)             │
│  Logic:  LLM analyzes complexity                                │
│  Example:                                                        │
│    "Top 5 artists by track count"                               │
│    → Need: Artist table, Track table                            │
│    → Join: Artist.ArtistId = Album.ArtistId                     │
│           Album.AlbumId = Track.AlbumId                         │
│    → Aggregate: COUNT tracks GROUP BY artist                    │
│    → Order: DESC LIMIT 5                                        │
└─────────────────────────────────────────────────────────────────┘
                            │
                            ▼
┌─────────────────────────────────────────────────────────────────┐
│  Agent #5: DataExplorer (Rule-based)                            │
│  ─────────────────────────────────────────────────────────────  │
│  Input:  Tables identified by QueryDecomposer                   │
│  Output: Sample data from relevant tables                       │
│  Logic:  SELECT * FROM table LIMIT 3                            │
│  Example:                                                        │
│    Artist: (1, 'AC/DC'), (2, 'Accept')...                       │
│    Track: Sample 3 rows showing track names                     │
└─────────────────────────────────────────────────────────────────┘
                            │
                            ▼
┌─────────────────────────────────────────────────────────────────┐
│  Agent #6: QueryPlanner                                         │
│  ─────────────────────────────────────────────────────────────  │
│  Input:  Schema + sample data + user query                      │
│  Output: Execution plan (joins, filters, aggregations)          │
│  Logic:  LLM designs SQL strategy                               │
│  Example Plan:                                                   │
│    1. JOIN Artist → Album → Track                               │
│    2. GROUP BY Artist.Name                                      │
│    3. COUNT(Track.TrackId)                                      │
│    4. ORDER BY count DESC                                       │
│    5. LIMIT 5                                                   │
└─────────────────────────────────────────────────────────────────┘
```

---

### **BATCH 3: SQL Generation & Safety Validation**
**LLM Calls:** 1 (+ retries if needed) | **Duration:** ~800ms + retries

```
┌─────────────────────────────────────────────────────────────────┐
│  Agent #7: SQLGenerator                                         │
│  ─────────────────────────────────────────────────────────────  │
│  Input:  Query plan + schema + sample data                      │
│  Output: SQL query (structured JSON with explanation)           │
│  Logic:  LLM generates SQL following plan                       │
│  Example Output:                                                 │
│    {                                                             │
│      "sql": "SELECT Artist.Name, COUNT(*) as tracks            │
│              FROM Artist                                        │
│              JOIN Album ON Artist.ArtistId = Album.ArtistId    │
│              JOIN Track ON Album.AlbumId = Track.AlbumId       │
│              GROUP BY Artist.Name                               │
│              ORDER BY tracks DESC LIMIT 5",                     │
│      "explanation": "Joins artist to tracks, counts..."         │
│    }                                                             │
└─────────────────────────────────────────────────────────────────┘
                            │
                            ▼
┌─────────────────────────────────────────────────────────────────┐
│  Agent #8: SafetyValidator (🛡️ CRITICAL GATE)                   │
│  ─────────────────────────────────────────────────────────────  │
│  Input:  Generated SQL                                          │
│  Output: APPROVED or BLOCKED + reason                           │
│  Rules: (HARDCODED - NOT BYPASSED)                              │
│    ✓ Check: Only SELECT allowed                                │
│    ✓ Check: No SELECT * (explicit columns required)            │
│    ✓ Check: LIMIT clause required                              │
│    ✓ Check: No forbidden keywords (DROP, DELETE, etc.)         │
│    ✓ Check: Row limit ≤ 1000                                   │
│  Example:                                                        │
│    ✅ APPROVED: "SELECT Name, Email FROM Customer LIMIT 10"    │
│    ❌ BLOCKED: "SELECT * FROM Customer"                         │
│                (Reason: SELECT * not allowed)                   │
└─────────────────────────────────────────────────────────────────┘
                            │
                ┌───────────┴───────────┐
                ▼                       ▼
           APPROVED                  BLOCKED
                │                       │
                ▼                       ▼
┌─────────────────────────────┐  Return Error Message
│  Agent #9: SQLExecutor      │       [END]
│  ─────────────────────────  │
│  Input:  Approved SQL       │
│  Output: Query results      │
│  Logic:  Execute on SQLite  │
│  Safety: Read-only mode     │
└─────────────────────────────┘
                │
        ┌───────┴───────┐
        ▼               ▼
    SUCCESS          FAILURE
        │               │
        │               ▼
        │     ┌─────────────────────────────┐
        │     │ Agent #10: SelfCorrection   │
        │     │ ─────────────────────────── │
        │     │ Input:  Error + SQL + plan  │
        │     │ Output: Fixed SQL           │
        │     │ Logic:  LLM analyzes error  │
        │     │ Retries: Max 3 attempts     │
        │     │ Example:                    │
        │     │   Error: "no such column"   │
        │     │   → Check schema again      │
        │     │   → Fix column name         │
        │     │   → Retry execution         │
        │     └─────────────────────────────┘
        │               │
        │               └──> Back to SQLExecutor
        │                    (Retry with fixed SQL)
        ▼
┌─────────────────────────────────────┐
│  Agent #11: ResultValidator         │
│  ───────────────────────────────── │
│  Input:  Query results              │
│  Output: Validation status          │
│  Checks:                             │
│    ✓ Results not empty (or OK)      │
│    ✓ Row count reasonable           │
│    ✓ Data types expected            │
└─────────────────────────────────────┘
```

---

### **BATCH 4: Response Synthesis**
**LLM Calls:** 1 | **Duration:** ~500ms

```
┌─────────────────────────────────────────────────────────────────┐
│  Agent #12: ResponseSynthesizer                                 │
│  ─────────────────────────────────────────────────────────────  │
│  Input:  Query results + SQL + reasoning trace                  │
│  Output: Human-readable answer + formatted data                 │
│  Logic:  LLM converts data to natural language                  │
│  Example:                                                        │
│    Input Results:                                               │
│      [('Iron Maiden', 213), ('Led Zeppelin', 114), ...]         │
│                                                                  │
│    Output Answer:                                               │
│      "The top 5 artists by track count are:                     │
│       1. Iron Maiden - 213 tracks                               │
│       2. Led Zeppelin - 114 tracks                              │
│       3. Deep Purple - 92 tracks                                │
│       4. Metallica - 112 tracks                                 │
│       5. U2 - 135 tracks"                                       │
│                                                                  │
│    Also includes:                                               │
│      • SQL query used                                           │
│      • Data preview (table format)                              │
│      • Full reasoning trace (all 12 agent actions)              │
└─────────────────────────────────────────────────────────────────┘
```

---

## 🔄 Special Flow: Self-Correction Loop

```
SQL Execution FAILS
        │
        ▼
┌─────────────────────────────┐
│  Capture Error              │
│  • Error message            │
│  • Failed SQL               │
│  • Execution context        │
└─────────────────────────────┘
        │
        ▼
┌─────────────────────────────┐     Retry Count < 3?
│  SelfCorrection Agent       │ ─────────┬─────────┐
│  • Analyze error            │          │         │
│  • Diagnose root cause      │         YES       NO
│  • Generate fix             │          │         │
└─────────────────────────────┘          │         ▼
        │                                │    Return Error
        ▼                                │      [END]
  Fixed SQL                              │
        │                                │
        └────────────────────────────────┘
                    │
                    ▼
            Retry Execution
```

**Common Fixes:**
- Column name typos → Check schema, fix name
- Missing JOIN → Add required join
- Wrong aggregation → Correct GROUP BY
- Syntax errors → Fix SQL syntax

---

## 📈 Performance Metrics

### Execution Time Breakdown

```
BATCH 1: Intent Analysis     ~500ms  ████████░░░░░░░░░░ 20%
BATCH 2: Schema & Planning    ~800ms  █████████████░░░░░ 32%
BATCH 3: SQL Generation       ~800ms  █████████████░░░░░ 32%
BATCH 4: Response Synthesis   ~500ms  ████████░░░░░░░░░░ 20%
                              ─────
Total (no retries):          ~2.6s   ████████████████████ 100%

With 1 retry:                ~3.4s
With 3 retries (worst):      ~5.0s
```

### LLM Call Distribution

```
Intent Analysis:        1 call  ┃████████████████████████████┃
Schema Exploration:     1 call  ┃████████████████████████████┃
SQL Generation:         1 call  ┃████████████████████████████┃
Self-Correction:      0-3 calls ┃░░░░░░░░░░░░░░░░░░░░░░░░░░░░┃
Response Synthesis:     1 call  ┃████████████████████████████┃
                        ─────
Total:                 4-7 calls (average: 4.2)
```

---

## 🎭 Agent Roles Summary

### 🧠 LLM-Based Agents (7)
Intelligent decision-making requiring reasoning:

1. **IntentAnalyzer** - Query classification
2. **ClarificationAgent** - Ambiguity resolution
4. **QueryDecomposer** - Break down complex queries
6. **QueryPlanner** - Design execution strategy
7. **SQLGenerator** - Generate SQL code
10. **SelfCorrection** - Fix errors and retry
12. **ResponseSynthesizer** - Human-friendly answers

### 📦 Rule-Based Agents (5)
Deterministic logic, no LLM needed:

3. **SchemaExplorer** - Database metadata inspection
5. **DataExplorer** - Sample data retrieval
8. **SafetyValidator** - Security enforcement (CRITICAL)
9. **SQLExecutor** - Query execution
11. **ResultValidator** - Sanity checks

---

## 🚨 Critical Decision Points

### 1. Intent Classification (Agent #1)
```
User Query → IntentAnalyzer
              │
    ┌─────────┼─────────┐
    ▼         ▼         ▼
DATA_QUERY  META    AMBIGUOUS
    │        │         │
Continue   Schema   Clarify
           [END]    [END]
```

### 2. Safety Validation (Agent #8)
```
Generated SQL → SafetyValidator
                   │
           ┌───────┴───────┐
           ▼               ▼
       APPROVED         BLOCKED
           │               │
       Execute         Return Error
                         [END]
```

### 3. Execution Result (Agent #9)
```
SQL Execution
      │
  ┌───┴───┐
  ▼       ▼
SUCCESS  FAILURE
  │       │
Continue  └──> SelfCorrection
              (if retries < 3)
```

---

## 💡 Example: Complete Pipeline Trace

**Query:** "Show me the top 5 artists by number of tracks"

```
STEP 1: Intent Analysis (500ms)
  └─> Agent #1: IntentAnalyzer
      ├─> Input: "Show me the top 5 artists by number of tracks"
      └─> Output: DATA_QUERY
      
STEP 2: Schema Exploration (800ms)
  ├─> Agent #3: SchemaExplorer
  │   └─> Output: Tables: Artist, Album, Track (with relationships)
  ├─> Agent #4: QueryDecomposer
  │   └─> Output: Need Artist-Album-Track join + COUNT + GROUP BY
  ├─> Agent #5: DataExplorer
  │   └─> Output: Sample data from Artist, Album, Track
  └─> Agent #6: QueryPlanner
      └─> Output: Join strategy + aggregation plan
      
STEP 3: SQL Generation (800ms)
  ├─> Agent #7: SQLGenerator
  │   └─> Output: SELECT Artist.Name, COUNT(*) as tracks...
  ├─> Agent #8: SafetyValidator
  │   └─> Output: APPROVED (has LIMIT, explicit columns)
  ├─> Agent #9: SQLExecutor
  │   └─> Output: [('Iron Maiden', 213), ('Led Zeppelin', 114)...]
  └─> Agent #11: ResultValidator
      └─> Output: VALID (5 rows returned)
      
STEP 4: Response Synthesis (500ms)
  └─> Agent #12: ResponseSynthesizer
      └─> Output: "The top 5 artists by track count are:
                   1. Iron Maiden - 213 tracks
                   2. Led Zeppelin - 114 tracks..."
      
Total Time: 2.6s
LLM Calls: 4
Status: ✅ SUCCESS
```

---

## 🎯 Key Innovations

### 1. Batch Optimization
- Groups agents into 4 LLM calls (not 7)
- Reduces API costs by ~43%
- Faster execution (parallel processing where possible)

### 2. Safety-First Architecture
- Agent #8 (SafetyValidator) is a **hard gate**
- Cannot be bypassed or influenced by LLM
- Prevents destructive operations

### 3. Self-Healing Pipeline
- Automatic error detection
- Intelligent retry with fixes
- Max 3 attempts (prevents infinite loops)

### 4. Multi-Provider Fallback
- Primary: Gemini (4 keys with auto-rotation)
- Fallback: Groq (on quota exhaustion)
- Zero downtime during demos

### 5. Full Transparency
- Every agent action logged
- Complete reasoning trace visible
- Debugging-friendly architecture

---

## 📚 Further Reading

- [Batch Orchestrator Design](docs/BATCH_ORCHESTRATOR_DESIGN.md)
- [Quota Optimization](docs/QUOTA_OPTIMIZATION.md)
- [Execution Flow Diagram](docs/EXECUTION_FLOW_DIAGRAM.md)
- [JSON Parsing Fix](docs/JSON_PARSING_FIX.md)
- [State Consistency Fix](docs/STATE_CONSISTENCY_FIX.md)

---

**Built with:** CrewAI • Gemini/Groq • SQLite • Streamlit  
**Performance:** 85%+ accuracy • 2-5s response time • 4-7 LLM calls
