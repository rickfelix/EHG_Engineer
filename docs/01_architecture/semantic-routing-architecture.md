# Semantic Intent Routing - Architecture

**Category**: Architecture
**Status**: Active
**Version**: 1.0.0
**Author**: LEO Protocol System
**Last Updated**: 2026-01-23
**Tags**: architecture, semantic-routing, embeddings, vector-search, sub-agents, skills
**Related SD**: SD-LEO-INFRA-SEMANTIC-ROUTING-001

---

## Overview

The Semantic Intent Routing System is a two-part infrastructure that uses OpenAI embeddings and cosine similarity to route user queries intelligently:

1. **Sub-Agent Router** - Routes queries to appropriate sub-agents (26 agents, 77% accuracy)
2. **Skill Intent Detector** - Detects skill invocation intent from user messages (12 skills, 100% accuracy)

This replaces keyword-based pattern matching with semantic understanding, solving critical issues:
- "identify the root cause" → Now routes to RCA agent (was no match)
- "yes, create the SD" → Now invokes `/leo create` skill (was no match)

---

## Architecture Diagram

```
┌─────────────────────────────────────────────────────────────────┐
│                        User Query                               │
│                 "identify the root cause"                       │
└────────────────────────┬────────────────────────────────────────┘
                         │
                         ├─────────────────┬─────────────────────┐
                         │                 │                     │
                         ▼                 ▼                     ▼
              ┌──────────────────┐  ┌──────────────┐  ┌────────────────┐
              │  Sub-Agent       │  │   Skill      │  │   Keyword      │
              │  Router          │  │   Intent     │  │   Fallback     │
              │  (Semantic)      │  │   Detector   │  │   (Legacy)     │
              └────────┬─────────┘  └──────┬───────┘  └────────┬───────┘
                       │                   │                   │
                       │ Embedding         │ Embedding         │ Regex
                       │ (OpenAI)          │ (OpenAI)          │
                       │                   │                   │
                       ▼                   ▼                   ▼
              ┌──────────────────┐  ┌──────────────┐  ┌────────────────┐
              │  Sub-Agent       │  │   Skill      │  │   Pattern      │
              │  Embeddings      │  │   Pattern    │  │   Keywords     │
              │  (DB: pgvector)  │  │   Embeddings │  │   (Hardcoded)  │
              │  26 agents x     │  │   (Cached)   │  │                │
              │  1536 dims       │  │   12 skills  │  │                │
              └────────┬─────────┘  └──────┬───────┘  └────────┬───────┘
                       │                   │                   │
                       │ Cosine            │ Cosine +          │ Exact
                       │ Similarity        │ Exact Match       │ Match
                       │                   │                   │
                       ▼                   ▼                   ▼
              ┌──────────────────┐  ┌──────────────┐  ┌────────────────┐
              │  Ranked Matches  │  │   Top Match  │  │   Matches      │
              │  RCA      (58%)  │  │   /leo       │  │   Yes/No       │
              │  TESTING  (42%)  │  │   create     │  │                │
              │  (Top 5, >35%)   │  │   (>45%)     │  │                │
              └────────┬─────────┘  └──────┬───────┘  └────────┬───────┘
                       │                   │                   │
                       ▼                   ▼                   ▼
              ┌──────────────────────────────────────────────────────┐
              │           Claude Code Decision Layer                 │
              │  - Invokes Task tool with top sub-agent              │
              │  - Invokes Skill tool if skill detected              │
              │  - Falls back to keyword if semantic fails            │
              └──────────────────────────────────────────────────────┘
```

---

## Component Design

### 1. Sub-Agent Router (`lib/semantic-agent-router.js`)

**Purpose**: Route user queries to appropriate sub-agents using semantic similarity.

**Class**: `SemanticAgentRouter`

**Key Methods**:

```javascript
class SemanticAgentRouter {
  constructor(options = {})
  async loadAgents()                    // Load sub-agents with embeddings (cached)
  async generateQueryEmbedding(query)   // Generate OpenAI embedding for query
  async route(query, options = {})      // Route query to top sub-agents
  async keywordFallback(query)          // Fallback to keyword matching
  async runTests()                      // Built-in testing suite
}
```

**Algorithm**:

```python
def route(query):
    # 1. Generate query embedding
    query_embedding = openai.embed(query)

    # 2. Load sub-agent embeddings from database
    agents = db.query("SELECT * FROM leo_sub_agents WHERE active = true")

    # 3. Calculate cosine similarity for each agent
    scores = []
    for agent in agents:
        similarity = cosine_similarity(query_embedding, agent.domain_embedding)
        scores.append({
            'code': agent.code,
            'score': similarity * 100  # Convert to percentage
        })

    # 4. Filter by threshold (35%) and return top 5
    matches = filter(lambda x: x.score >= 35, scores)
    return sorted(matches, key=lambda x: x.score, reverse=True)[:5]
```

**Cosine Similarity Implementation**:

```javascript
function cosineSimilarity(a, b) {
  // Parse vectors (handles PostgreSQL string format)
  const vecA = parseVector(a);  // "[0.1,0.2,...]" → [0.1, 0.2, ...]
  const vecB = parseVector(b);

  if (!vecA || !vecB || vecA.length !== vecB.length) return 0;

  let dotProduct = 0;
  let normA = 0;
  let normB = 0;

  for (let i = 0; i < vecA.length; i++) {
    dotProduct += vecA[i] * vecB[i];
    normA += vecA[i] * vecA[i];
    normB += vecB[i] * vecB[i];
  }

  const magnitude = Math.sqrt(normA) * Math.sqrt(normB);
  return magnitude === 0 ? 0 : dotProduct / magnitude;
}
```

**Caching Strategy**:
- Agent embeddings cached with 5-minute TTL
- Cache invalidated on new agent or updated description
- Cache key: timestamp-based expiry

---

### 2. Skill Intent Detector (`lib/skill-intent-detector.js`)

**Purpose**: Detect when user messages should trigger skill invocations.

**Class**: `SkillIntentDetector`

**Key Methods**:

```javascript
class SkillIntentDetector {
  constructor(options = {})
  async loadPatternEmbeddings()         // Generate embeddings for skill patterns (cached)
  async generateMessageEmbedding(msg)   // Generate embedding for user message
  async detect(message, options = {})   // Detect skill intent
  async runTests()                      // Built-in testing suite
}
```

**Algorithm**:

```python
def detect(message):
    # 1. Load skill pattern embeddings (cached)
    patterns = load_pattern_embeddings()  # Only generated once

    # 2. Generate message embedding
    message_embedding = openai.embed(message)

    # 3. Calculate similarity for each skill
    scores = []
    for skill, pattern in patterns.items():
        semantic_score = cosine_similarity(message_embedding, pattern.embedding)

        # 4. Check for exact pattern matches (bonus)
        exact_match = any(pattern.lower() in message.lower()
                          for pattern in skill.patterns)

        # 5. Combined score with 20% bonus for exact match
        combined_score = semantic_score + (0.2 if exact_match else 0)

        scores.append({
            'skill': skill.name,
            'semantic': semantic_score * 100,
            'exact_match': exact_match,
            'combined': min(combined_score, 1.0) * 100
        })

    # 6. Return top match if above 45% threshold
    top_match = max(scores, key=lambda x: x.combined)
    return top_match if top_match.combined >= 45 else None
```

**Hybrid Scoring**:
- **Semantic similarity**: 0-100% (cosine similarity)
- **Exact match bonus**: +20% if any pattern found in message
- **Combined score**: `min(semantic + bonus, 100%)`

**Why Hybrid?**:
- Pure semantic: "yes, create the SD" → 37% (below threshold)
- With exact match: 37% + 20% = 57% ✅ (above 45% threshold)

---

### 3. Embedding Generator (`scripts/generate-subagent-embeddings.js`)

**Purpose**: Generate and store domain embeddings for all sub-agents.

**Process**:

```
1. Load SUB_AGENT_DOMAINS object (26 agents)
   ├─ RCA: "Root Cause Analysis and Debugging..."
   ├─ DATABASE: "Schema design, migrations..."
   └─ ... (24 more)

2. For each sub-agent:
   ├─ Generate embedding via OpenAI API
   │  └─ Model: text-embedding-3-small
   │  └─ Dimensions: 1536
   │  └─ Cost: ~$0.000004 per agent
   │
   ├─ Store in database
   │  └─ Table: leo_sub_agents
   │  └─ Column: domain_embedding (vector(1536))
   │
   └─ Log progress

3. Summary:
   └─ Total agents: 26
   └─ Total cost: $0.0001
   └─ Coverage: 100%
```

**Domain Description Format**:

```javascript
const SUB_AGENT_DOMAINS = {
  RCA: `Root Cause Analysis and Debugging.
    Systematic problem investigation, root cause identification,
    5 Whys methodology, fishbone diagrams (Ishikawa),
    fault tree analysis, causal chain analysis,
    debugging strategies, error log analysis, stack trace interpretation,
    identify the root cause, find the source of bugs, why is this failing,
    trace the issue, dig deeper into the problem, diagnostic reasoning,
    hypothesis testing, evidence collection, symptom vs cause distinction,
    regression analysis, change impact analysis, dependency tracing,
    correlation vs causation, contributing factors identification,
    incident timeline reconstruction, post-incident analysis, blameless postmortems`
};
```

**Why This Format?**:
- **Comprehensive**: Covers formal terms + conversational phrases
- **Natural language**: Matches how users actually ask questions
- **Keyword-rich**: Includes domain-specific vocabulary
- **Action-oriented**: "identify", "find", "trace" (verbs users use)

---

## Data Flow

### Sub-Agent Routing Flow

```
[User Query: "identify the root cause"]
         ↓
[SemanticAgentRouter.route()]
         ↓
[OpenAI API: Generate query embedding]
         ↓ (100-200ms)
[Query Embedding: [0.123, -0.456, ...] (1536 dims)]
         ↓
[Load agent embeddings from DB (cached)]
         ↓
[Calculate cosine similarity for 26 agents]
         ↓ (< 10ms)
[Similarity Scores:
   RCA: 0.58
   TESTING: 0.42
   DATABASE: 0.31
   ... (23 more)]
         ↓
[Filter by threshold (0.35)]
         ↓
[Ranked Results:
   1. RCA (58%)
   2. TESTING (42%)]
         ↓
[Return top 5 matches]
```

### Skill Detection Flow

```
[User Message: "yes, create the SD"]
         ↓
[SkillIntentDetector.detect()]
         ↓
[OpenAI API: Generate message embedding]
         ↓ (100-200ms)
[Message Embedding: [0.234, -0.567, ...]]
         ↓
[Load skill pattern embeddings (cached)]
         ↓
[Calculate semantic similarity for 12 skills]
         ↓
[Check for exact pattern matches]
         ↓
[Hybrid Scoring:
   /leo create:
     - Semantic: 37%
     - Exact match: "create" found → +20%
     - Combined: 57%
   /ship:
     - Semantic: 12%
     - Exact match: No
     - Combined: 12%
   ... (10 more)]
         ↓
[Top match: /leo create (57%) > 45% threshold ✅]
         ↓
[Return { skill: "leo create", combined: 57 }]
```

---

## Database Schema

### leo_sub_agents Table

```sql
CREATE TABLE leo_sub_agents (
  id UUID PRIMARY KEY DEFAULT uuid_generate_v4(),
  code TEXT UNIQUE NOT NULL,           -- 'RCA', 'DATABASE', etc.
  name TEXT,                            -- Human-readable name
  description TEXT,                     -- Brief description
  priority INTEGER DEFAULT 0,           -- Execution priority
  domain_embedding vector(1536),        -- OpenAI embedding (pgvector)
  active BOOLEAN DEFAULT true,
  metadata JSONB,                       -- Flexible metadata
  created_at TIMESTAMPTZ DEFAULT NOW(),
  updated_at TIMESTAMPTZ DEFAULT NOW()
);

-- Indexes
CREATE INDEX idx_leo_sub_agents_active
  ON leo_sub_agents(active)
  WHERE active = true;

CREATE INDEX idx_leo_sub_agents_priority
  ON leo_sub_agents(priority DESC);
```

**Vector Storage**:
- Extension: `pgvector`
- Type: `vector(1536)`
- Format: PostgreSQL stores as string: `"[0.123,-0.456,...]"`
- Parsing: Custom `parseVector()` function converts to array

**Sample Row**:
```json
{
  "id": "uuid-here",
  "code": "RCA",
  "name": "Root Cause Analysis Agent",
  "description": "Systematic problem investigation and debugging",
  "priority": 10,
  "domain_embedding": "[0.0123,-0.0456,0.0789,...]",  // 1536 values
  "active": true,
  "metadata": {
    "trigger_keywords": ["root cause", "5 whys", "debug"]
  },
  "created_at": "2026-01-23T...",
  "updated_at": "2026-01-23T..."
}
```

---

## Performance Characteristics

### Latency

| Operation | Cold Start | Warm (Cached) |
|-----------|------------|---------------|
| Generate query embedding | 100-200ms | 100-200ms |
| Load agent embeddings | 50ms (DB) | < 1ms (cache) |
| Calculate similarities (26 agents) | < 10ms | < 10ms |
| **Total Sub-Agent Routing** | **~250ms** | **~100ms** |
| Generate skill embeddings | 300ms (12 skills) | < 1ms (cached) |
| **Total Skill Detection** | **~300ms** | **~100ms** |

**Bottleneck**: OpenAI API call (100-200ms)
**Optimization**: Caching agent/skill embeddings (saves 50-300ms)

### Accuracy

**Sub-Agent Routing** (30 test queries):
| Result | Count | Percentage |
|--------|-------|------------|
| Correct match | 23 | 77% |
| Incorrect match | 1 | 3% |
| No match (< 35%) | 6 | 20% |

**Skill Detection** (9 test queries):
| Result | Count | Percentage |
|--------|-------|------------|
| Correct match | 9 | 100% |
| Incorrect match | 0 | 0% |
| No match (< 45%) | 0 | 0% |

**False Positive Analysis**:
- **Sub-Agent**: "review authentication flow" → UAT (36%) instead of SECURITY
  - Reason: Both agents have "authentication" in domain descriptions
  - Severity: Low (UAT still relevant for auth testing)

**False Negative Analysis**:
- **Sub-Agent**: "why is this slow" → No match (< 35%)
  - Reason: Query too vague (no domain-specific context)
  - Solution: User should provide more context

### Cost

**Embedding Generation** (one-time):
- 26 sub-agents × ~600 tokens each = ~15,600 tokens
- Cost: $0.02/1M tokens × 15,600 = **$0.00031**

**Skill Patterns** (one-time per session):
- 12 skills × ~150 tokens each = ~1,800 tokens
- Cost: $0.02/1M tokens × 1,800 = **$0.000036**

**Query Routing** (per request):
- 1 query × ~100 tokens = 100 tokens
- Cost: $0.02/1M tokens × 100 = **$0.000002**

**Monthly Estimate** (1000 queries/day):
- Generation: $0.00031 (one-time)
- 30,000 queries: $0.06
- **Total: $0.06/month**

---

## Design Decisions

### 1. Why Cosine Similarity (Not Euclidean)?

**Cosine Similarity**:
- Measures angle between vectors
- Invariant to magnitude (vector length)
- Range: -1 to 1 (normalized)
- Best for text embeddings (direction matters more than magnitude)

**Euclidean Distance**:
- Measures absolute distance
- Sensitive to magnitude
- Range: 0 to ∞ (unbounded)
- Better for spatial coordinates

**Example**:
```
Query: "identify root cause" → [0.5, 0.5, 0.0]
Agent: "Root Cause Analysis" → [0.7, 0.7, 0.0]

Cosine Similarity:
  cos(θ) = (0.5×0.7 + 0.5×0.7 + 0.0×0.0) / (√0.5 + √0.5)
         = 0.7 / 1.0 = 0.7 (70%) ✅

Euclidean Distance:
  d = √((0.5-0.7)² + (0.5-0.7)² + 0²)
    = √0.08 = 0.28 ❌ (no semantic meaning)
```

### 2. Why 35% Threshold for Sub-Agents?

**Tested Thresholds**:
- **65%**: Too high → 0% matches (all queries failed)
- **50%**: Still too high → ~30% matches
- **35%**: Balanced → 77% matches ✅
- **25%**: Too low → False positives

**Distribution of Actual Similarities**:
```
RCA queries: 40-60% (root cause, debug, investigate)
Database queries: 45-65% (schema, migration, RLS)
Performance queries: 35-50% (optimize, slow, bottleneck)
Ambiguous queries: 20-35% (too vague, no match OK)
```

**Decision**: 35% captures genuine semantic matches while filtering noise.

### 3. Why 45% Threshold for Skills (Higher Than Sub-Agents)?

**Reason**: Skills require higher precision (false positives are worse).

**Impact of False Positive**:
- Sub-agent: Claude invokes wrong agent → Minor delay, can recover
- Skill: System auto-runs wrong command → Could ship unintended code ❌

**With Exact Match Bonus**:
- Most genuine skill intents include pattern keywords
- "yes, create the SD" → 37% semantic + 20% bonus = 57% ✅
- Generic phrases without patterns → Stay below 45% ✅

### 4. Why Hybrid Scoring (Semantic + Exact Match)?

**Pure Semantic Issues**:
- "yes" → Too generic (37% for /leo create)
- "create the SD" → Better but borderline (42%)
- "yes, create the SD" → 37% (FAILS at 45% threshold)

**With Exact Match Bonus**:
- "yes, create the SD" → Contains "create" pattern → +20% → 57% ✅
- "absolutely, go ahead and create it" → Contains "create" → +20% → 63% ✅

**Benefit**: Catches conversational affirmatives that pure semantic misses.

### 5. Why Client-Side Similarity (Not Database Function)?

**Attempted**:
```sql
CREATE FUNCTION match_sub_agents_semantic(query_embedding vector(1536))
RETURNS TABLE(code text, similarity float)
AS $$
  SELECT code, 1 - (domain_embedding <-> query_embedding) as similarity
  FROM leo_sub_agents
  WHERE active = true
  ORDER BY similarity DESC
  LIMIT 5;
$$ LANGUAGE sql;
```

**Problem**: Type mismatch error, RPC function inconsistencies.

**Solution**: Implement cosine similarity in JavaScript.

**Benefits**:
- ✅ Full control over algorithm
- ✅ Better error handling
- ✅ Easier debugging
- ✅ Portable (works without DB function)

**Trade-off**: Slightly slower (~10ms) but negligible vs API latency (100ms).

---

## Edge Cases

### 1. Ambiguous Queries

**Example**: "review authentication flow"
- **Could be**: SECURITY (auth implementation) or UAT (auth testing)
- **Current**: Routes to UAT (36%)
- **Resolution**: Acceptable ambiguity (both agents valid)

### 2. Very Short Queries

**Example**: "why"
- **Similarity**: All agents < 20%
- **Result**: No match (correctly filtered)
- **Resolution**: User should provide more context

### 3. Domain Overlap

**Example**: "database performance issues"
- **Matches**: DATABASE (55%), PERFORMANCE (50%)
- **Current**: Returns both in top 5
- **Resolution**: Claude can invoke both agents if needed

### 4. New/Unseen Vocabulary

**Example**: "refrobulate the schmorgleblatt"
- **Similarity**: Random noise (15-25%)
- **Result**: No match (correctly filtered)
- **Resolution**: Semantic similarity handles unseen words gracefully

---

## Testing Strategy

### Unit Tests

```bash
# Test sub-agent routing with known queries
node lib/semantic-agent-router.js --test

# Test skill detection with known messages
node lib/skill-intent-detector.js --test
```

### Integration Tests

```bash
# Test end-to-end with real queries
node lib/semantic-agent-router.js "identify the root cause of authentication failures"

# Expected: RCA (58%), SECURITY (42%)
```

### Regression Tests

**Baseline Queries** (must always route correctly):
- "identify the root cause" → RCA
- "create database migration" → DATABASE
- "yes, create the SD" → /leo create
- "commit this and create a PR" → /ship

**Stored in**: `scripts/test-semantic-routing.js` (to be created)

---

## Migration Path

### From Keyword-Based to Semantic

**Before** (Keyword-based):
```javascript
// CLAUDE.md: Sub-Agent Trigger Keywords
if (query.includes('root cause') || query.includes('debug')) {
  invokeAgent('RCA');
}
```

**After** (Semantic):
```javascript
const router = new SemanticAgentRouter();
const matches = await router.route(query);
if (matches.length > 0) {
  invokeAgent(matches[0].code);  // Top match
}
```

**Hybrid Approach** (Current):
- ✅ Semantic routing runs first
- ✅ Keyword fallback if no semantic match
- ✅ Gradual migration (both systems coexist)

---

## Security Considerations

### API Key Storage

**Critical**: `OPENAI_API_KEY` must be in `.env` (never committed).

```bash
# .env
OPENAI_API_KEY=sk-...

# .gitignore
.env
```

### Rate Limiting

**OpenAI Limits**:
- Free tier: 3 RPM (requests per minute)
- Paid tier: 3,500 RPM

**Current Usage**: ~1 request per user query (well below limits)

**Mitigation**: Caching reduces API calls by 80% (embeddings reused).

### Data Privacy

**Queries Sent to OpenAI**:
- ✅ User queries (necessary for embedding)
- ✅ Sub-agent domain descriptions (one-time)
- ❌ No user data, passwords, or secrets

**Storage**:
- Embeddings stored in database (no raw query data)
- Query logs not persisted

---

## References

### Related Systems
- **Keyword-Based Triggering**: `docs/reference/preventing-missed-subagents.md`
- **Sub-Agent System**: CLAUDE.md (Sub-Agent Trigger Keywords)
- **Skill System**: CLAUDE.md (Skill Intent Detection)

### External References
- **OpenAI Embeddings API**: https://platform.openai.com/docs/guides/embeddings
- **PostgreSQL pgvector**: https://github.com/pgvector/pgvector
- **Cosine Similarity**: https://en.wikipedia.org/wiki/Cosine_similarity
- **Vector Databases**: https://www.pinecone.io/learn/vector-database/

### Source Code
- **Sub-Agent Router**: `lib/semantic-agent-router.js` (272 lines)
- **Skill Detector**: `lib/skill-intent-detector.js` (411 lines)
- **Embedding Generator**: `scripts/generate-subagent-embeddings.js`

---

## Integration with Claude Code Hooks

**Status**: ✅ Integrated (2026-01-24)
**Related SD**: SD-LEO-INFRA-INTEGRATE-SEMANTIC-ROUTER-001

### Hook Implementation

The semantic router is now integrated into Claude Code's execution lifecycle via **UserPromptSubmit hook**.

**File**: `scripts/hooks/semantic-router-hook.js` (271 lines)

**Integration Point**: `.claude/settings.json`

```json
"UserPromptSubmit": [
  {
    "hooks": [
      {
        "type": "command",
        "command": "node C:/Users/rickf/Projects/_EHG/EHG_Engineer/scripts/hooks/semantic-router-hook.js",
        "timeout": 1
      },
      // ... other hooks
    ]
  }
]
```

### How It Works

1. **User submits prompt** → Claude Code triggers UserPromptSubmit hooks
2. **Hook receives stdin** → JSON payload: `{"prompt": "identify the root cause", "session_id": "..."}`
3. **Hook reads prompt** → Asynchronous stdin reading with 'readable' event pattern
4. **Generate embedding** → OpenAI API call (~100-200ms)
5. **Query database** → Load 26 sub-agent embeddings (cached)
6. **Calculate similarities** → Cosine similarity for all agents
7. **Filter and rank** → Top 3 matches above 35% threshold
8. **Output to stdout** → Format: `[SEMANTIC-ROUTE] Recommended sub-agents: RCA (41%), TESTING (38%)`
9. **Claude receives context** → Hook output appears as system-reminder
10. **Claude invokes agents** → Uses Task tool with recommended sub-agents

### Hook Architecture

```javascript
// scripts/hooks/semantic-router-hook.js

async function main() {
  // 1. Read user prompt from stdin
  const input = await readStdin();
  if (!input?.prompt) return gracefulExit();

  // 2. Route the prompt
  const { matches, latencyMs } = await routePrompt(input.prompt);

  // 3. Output recommendations
  if (matches.length > 0) {
    const formatted = matches.map(m => `${m.code} (${m.score}%)`).join(', ');
    console.log(`[SEMANTIC-ROUTE] Recommended sub-agents: ${formatted}`);
    console.error(`[DEBUG] Latency: ${latencyMs}ms`);
  }

  process.exit(0);
}
```

### Stdin Reading Pattern (Critical)

**Challenge**: Claude Code hooks receive buffered JSON via stdin, requiring synchronous-style read.

**Solution**: Use 'readable' event with `process.stdin.read()` loop:

```javascript
async function readStdin() {
  return new Promise((resolve) => {
    let data = '';
    let hasData = false;

    process.stdin.setEncoding('utf8');

    // CRITICAL: Use 'readable' event, not 'data'
    process.stdin.on('readable', () => {
      let chunk;
      while ((chunk = process.stdin.read()) !== null) {
        data += chunk;
        hasData = true;
      }
    });

    process.stdin.on('end', () => {
      if (hasData && data.trim()) {
        try {
          resolve(JSON.parse(data));
        } catch {
          resolve(null);
        }
      } else {
        resolve(null);
      }
    });

    // Handle TTY mode (no stdin)
    if (process.stdin.isTTY) {
      resolve(null);
    }
  });
}
```

**Why This Pattern?**:
- Simple `data`/`end` events returned `null` (buffered JSON not captured)
- `readable` event with `read()` loop handles buffered input correctly
- Gracefully handles TTY mode (direct terminal execution)

### Configuration

**Environment Variables**:

```bash
# .env
OPENAI_API_KEY=sk-...                      # Required
SUPABASE_URL=https://...                    # Required
SUPABASE_SERVICE_ROLE_KEY=...              # Required

# Optional Configuration
SEMANTIC_ROUTER_ENABLED=true               # Enable/disable hook
SEMANTIC_ROUTER_TIMEOUT_MS=500             # Max execution time
SEMANTIC_ROUTER_THRESHOLD=0.35             # Minimum similarity (35%)
SEMANTIC_ROUTER_TOP_K=3                    # Max recommendations
SEMANTIC_ROUTER_DEBUG=false                # Enable debug logging
```

**Defaults** (if env vars not set):
- Enabled: `true`
- Timeout: 500ms
- Threshold: 35%
- Top K: 3
- Debug: false

### Performance

| Metric | Target | Actual |
|--------|--------|--------|
| Latency (cold) | <500ms | ~300ms ✅ |
| Latency (warm) | <200ms | ~150ms ✅ |
| Hook timeout | 1000ms | No timeouts ✅ |
| OpenAI API call | ~200ms | ~150ms ✅ |
| Database query | <50ms | ~20ms ✅ |
| Similarity calc | <10ms | ~5ms ✅ |

**Bottleneck**: OpenAI API call (~150ms)
**Optimization**: Agent embeddings cached (saves ~20ms on DB query)

### Error Handling

**Graceful Fallback** (no user disruption):

```javascript
try {
  const matches = await routePrompt(prompt);
  outputRecommendations(matches);
} catch (error) {
  // Log error but don't block Claude Code
  console.error(`[ERROR] Semantic routing failed: ${error.message}`);
  process.exit(0);  // Exit cleanly (fallback to keyword matching)
}
```

**Error Scenarios**:
1. **OpenAI API down** → Hook exits cleanly, keyword matching continues
2. **Database connection fails** → Hook exits cleanly
3. **Invalid stdin JSON** → Hook exits cleanly
4. **Timeout (>500ms)** → Circuit breaker kills hook, keyword matching continues

**User Impact**: None (transparent fallback to keyword-based triggers)

### Testing

**Test Command**:
```bash
# Manual test with simulated stdin
echo '{"prompt":"identify the root cause","session_id":"test"}' | \
  node scripts/hooks/semantic-router-hook.js

# Expected output:
# [SEMANTIC-ROUTE] Recommended sub-agents: RCA (41%)
```

**Debug Mode**:
```bash
SEMANTIC_ROUTER_DEBUG=true node scripts/hooks/semantic-router-hook.js
```

**Test Results** (2026-01-24):
```
Query: "identify the root cause"
Output: [SEMANTIC-ROUTE] Recommended sub-agents: RCA (41%)
Latency: 287ms
Status: ✅ PASS
```

### Example User Interaction

**Before Integration** (keyword-only):
```
User: "identify the root cause of this bug"
Claude: [No sub-agent triggered - keywords 'root cause' not exact match]
Claude: Let me investigate manually...
```

**After Integration** (semantic routing):
```
User: "identify the root cause of this bug"
[Hook executes in background]
[SEMANTIC-ROUTE] Recommended sub-agents: RCA (41%)
Claude: [Sees recommendation in context]
Claude: I'll invoke the RCA sub-agent to systematically investigate...
[Invokes Task tool with subagent_type="RCA"]
```

### Integration Benefits

1. **Natural Language Understanding**: Conversational queries now route correctly
2. **Reduced Missed Matches**: 77% routing accuracy (vs ~50% keyword-only)
3. **Transparent**: Fallback to keywords if semantic fails
4. **Fast**: <300ms latency (imperceptible to users)
5. **Safe**: Graceful error handling, no session disruption
6. **Configurable**: Environment variables for tuning

### Maintenance

**Update Sub-Agent Domains**:
```bash
# 1. Edit domains in scripts/generate-subagent-embeddings.js
# 2. Regenerate embeddings
node scripts/generate-subagent-embeddings.js

# 3. Test routing with new domains
node lib/semantic-agent-router.js "test query here"
```

**Adjust Thresholds**:
```bash
# .env
SEMANTIC_ROUTER_THRESHOLD=0.40  # Raise for stricter matching
SEMANTIC_ROUTER_TOP_K=5         # Show more recommendations
```

**Monitor Performance**:
```bash
# Enable debug logging
SEMANTIC_ROUTER_DEBUG=true

# Check latency in stderr output
# [DEBUG] Latency: XXXms
```

### Known Limitations

1. **OpenAI Dependency**: Requires API access (fails gracefully if unavailable)
2. **Cold Start Latency**: First query ~300ms (acceptable, under 500ms target)
3. **Ambiguous Queries**: Very short queries (<3 words) may not match
4. **Cost**: ~$0.000002 per query (negligible: ~$0.06/month for 1000 queries/day)

### Future Enhancements

1. **Local Embeddings**: Use open-source models (Sentence Transformers) to eliminate OpenAI dependency
2. **Query Caching**: Cache query embeddings for repeated queries
3. **Feedback Loop**: Track which recommendations Claude actually uses, improve matching
4. **Hybrid Refinement**: Combine semantic + keyword scores (not just fallback)

---

## Migration to Weighted Keyword Scoring (2026-01-24)

### Decision

After evaluation and testing, the system was migrated from semantic routing back to **weighted keyword scoring** for the following reasons:

#### Comparison Analysis

| Aspect | Semantic Routing | Weighted Keyword Scoring |
|--------|-----------------|-------------------------|
| **Latency** | ~300ms (OpenAI API call) | <1ms (local matching) |
| **Cost** | $0.000002 per query (~$0.06/month for 1000 queries/day) | $0 (no external dependencies) |
| **Accuracy** | 77% | 100% (with comprehensive keywords) |
| **Reliability** | Depends on OpenAI API availability | 100% reliable (local) |
| **Determinism** | Non-deterministic (embeddings can vary) | Deterministic (same query → same result) |
| **Debuggability** | Hard to debug (black box embeddings) | Easy to debug (visible keyword matches) |
| **Maintenance** | Complex (database embeddings, API keys) | Simple (keyword lists in database) |

#### Key Insights

1. **Speed Over Sophistication**: Sub-millisecond latency matters more than semantic understanding for routing
2. **Keyword Coverage**: The semantic gap ("identify the root cause" not matching RCA) was solved by simply adding missing keywords
3. **Overfitting Preference**: Comprehensive keyword lists (primary/secondary/tertiary) achieve better accuracy than semantic matching
4. **No External Dependencies**: Eliminates OpenAI API dependency, reducing system fragility

### New Implementation: Weighted Keyword Scoring

**Implementation**: `lib/keyword-intent-scorer.js` (714 lines)

#### Scoring Formula

```
score = sum(matched_keyword_weights)
```

#### Weight Categories

| Category | Weight | Description | Example |
|----------|--------|-------------|---------|
| **PRIMARY** | 4 points | Unique to agent | "root cause" → RCA |
| **SECONDARY** | 2 points | Strong signal | "debug", "migration" |
| **TERTIARY** | 1 point | Common terms | "issue", "problem" |

#### Confidence Thresholds

| Threshold | Points | Action |
|-----------|--------|--------|
| **HIGH** | ≥5 | Auto-trigger agent |
| **MEDIUM** | ≥3 | Trigger if single match, suggest if multiple |
| **LOW** | ≥1 | Mention for awareness |

#### Examples

```
"identify the root cause" → RCA (4pts primary "root cause" + 1pt tertiary = 5pts = HIGH)
"create database migration" → DATABASE (4pts primary + 2pts secondary = 6pts = HIGH)
"this is slow" → PERFORMANCE (2pts secondary = MEDIUM)
```

#### Keyword Storage

Keywords stored in `leo_sub_agents.metadata.trigger_keywords`:

```json
{
  "primary": ["root cause", "5 whys", "fishbone"],
  "secondary": ["debug", "investigate", "diagnose"],
  "tertiary": ["broken", "failing", "error"]
}
```

#### Test Accuracy

**100% (16/16 tests passing)** - improved from 77% semantic accuracy.

#### Key Features

1. **Phrase-Aware Matching**: Multi-word phrases ("root cause") matched as units
2. **Word Boundary Matching**: Single words use `\b` word boundary regex
3. **Comprehensive Coverage**: 25 agents with 800+ total keywords
4. **Database-Driven**: Keywords stored in database for easy updates

### Migration Path

1. ✅ Disabled `semantic-router-hook.js` in `.claude/settings.json`
2. ✅ Created `lib/keyword-intent-scorer.js` with weighted scoring
3. ✅ Updated 25 agents with weighted keywords in database
4. ✅ Added `weighted_keyword_scoring` section to `leo_protocol_sections`
5. ✅ Regenerated CLAUDE.md files from database

### Semantic Router Status

**Status**: 🟡 Deprecated (2026-01-24)
**Reason**: Weighted keyword scoring provides better accuracy, speed, and reliability
**Code Status**: Preserved in codebase for reference (not deleted)
**Documentation Status**: This file preserved as architectural history

### Related Documentation

- **Weighted Scoring Implementation**: `docs/summaries/implementations/keyword-scoring-implementation.md`
- **Semantic Router Integration**: `docs/summaries/implementations/semantic-router-integration-complete.md` (historical)
- **CLAUDE_CORE.md**: Contains weighted keyword scoring section (auto-generated from database)

---

**Status**: 🟡 Deprecated (2026-01-24) - Migrated to weighted keyword scoring
**Integration**: ✅ Complete (Deployed 2026-01-24, Deprecated same day)
**Replacement**: Weighted keyword scoring system (`lib/keyword-intent-scorer.js`)
**Maintainer**: LEO Protocol Infrastructure Team
**Historical Reference**: System built and tested, but deprecated in favor of simpler approach
