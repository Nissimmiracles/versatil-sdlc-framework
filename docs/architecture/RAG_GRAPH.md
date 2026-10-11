# 🧠 RAG Memory System: Zero Context Loss

**Version**: v6.6.0
**Last Updated**: October 22, 2025
**Status**: Production

---

## 🎯 Overview

VERSATIL achieves **98%+ context retention** across sessions using a sophisticated **GraphRAG system** with **multi-tier caching** and **privacy-isolated storage**.

### The Problem It Solves

**Traditional AI assistants**:
- ❌ Lose context between sessions
- ❌ Can't remember past decisions
- ❌ Repeat same questions every time
- ❌ No learning from experience

**VERSATIL with RAG**:
- ✅ 98%+ context retention across sessions
- ✅ Remembers all patterns, decisions, conventions
- ✅ Never asks the same question twice
- ✅ Gets smarter with every feature you build

---

## 🏗️ Architecture

### System Overview

```
📥 INPUT → 🔄 PROCESS → 💾 STORE → ⚡ CACHE → 🎯 RETRIEVE → 📤 OUTPUT
```

### The 6 Layers

#### 1. **Input Layer** 📥

**What gets captured**:
- Your code (from git history)
- Agent decisions and actions
- User feedback and corrections
- Time estimates (planned vs actual)
- Error patterns and resolutions

**Example**:
```json
{
  "type": "code_pattern",
  "source": "git commit 8f4a2b1",
  "pattern": {
    "name": "async error handling",
    "code": "try { await fn() } catch (e) { logger.error(e) }",
    "frequency": "high",
    "user": "you@example.com"
  }
}
```

---

#### 2. **Processing Layer** 🔄

**Analysis Engine**:
- Extracts coding style patterns
- Identifies reusable templates
- Detects relationships between entities
- Classifies by domain, tech stack, complexity

**GraphRAG Builder**:
- Creates entity nodes (patterns, files, decisions)
- Links relationships (uses, similar-to, depends-on)
- Adds metadata (tags, timestamps, confidence scores)

**Example Graph**:
```
[Authentication Pattern]
  ├─ uses → [JWT Library]
  ├─ similar-to → [OAuth Pattern]
  ├─ depends-on → [User Model]
  └─ applied-in → [Feature #42]
```

---

#### 3. **Storage Layer** 💾

**Privacy-Isolated Storage**:

| Layer | Visibility | Purpose | Size Limit |
|-------|-----------|---------|------------|
| **User Patterns** | Private to YOU only | Your coding style, preferences | 100MB |
| **Team Conventions** | Shared with team | Team standards, linting rules | 50MB/team |
| **Project Vision** | Project contributors | Project goals, architecture | 20MB/project |
| **Framework Patterns** | Public | Universal best practices | Unlimited |

**Storage Format**: Vector embeddings + Graph relationships

**Database**: Supabase (PostgreSQL + pgvector)

---

#### 4. **Cache Layer** ⚡

**Multi-Tier Caching** (65% faster RAG queries):

```
┌─────────────┐
│ HOT Cache   │ In-memory, <1ms, 10MB, 95% hit rate
├─────────────┤
│ WARM Cache  │ Redis, <10ms, 100MB, 80% hit rate
├─────────────┤
│ COLD Cache  │ Vector DB, <50ms, unlimited, 60% hit rate
└─────────────┘
```

**Cache Invalidation**:
- HOT: Every 5 minutes
- WARM: Every 1 hour
- COLD: Never (vector DB is source of truth)

**Example**:
```
Query: "How do I handle auth errors?"
→ Check HOT cache: Miss
→ Check WARM cache: Hit! (10ms)
→ Return: "Use try/catch with logger.error(...)"
```

---

#### 5. **Retrieval Layer** 🎯

**Context Query**:
- **Semantic search**: Match by meaning (vector similarity)
- **Graph traversal**: Follow relationships (uses, similar-to)
- **Hybrid ranking**: Combine semantic + graph + recency

**CRG (Context Retrieval Graph)**:
```
User Query: "Add OAuth login"
→ Semantic: Find "OAuth" patterns (0.89 similarity)
→ Graph: Traverse to "JWT auth" (related)
→ Recency: Prefer patterns from last 30 days
→ Rank: Top 5 results with confidence scores
```

**Relevance Scoring**:
```
Score = (semantic_similarity * 0.5)
      + (graph_distance * 0.3)
      + (recency * 0.1)
      + (usage_frequency * 0.1)
```

---

#### 6. **Output Layer** 📤

**Context Augmentation**:
- Inject relevant patterns into agent prompts
- Add code templates and examples
- Include past decisions and rationale
- Attach time estimates and complexity scores

**CAG (Context Augmented Generation)**:
```
Agent Prompt (before):
"Implement OAuth login"

Agent Prompt (after CAG):
"Implement OAuth login

Relevant patterns from your past work:
1. JWT authentication (Feature #42, 125 min, success)
2. Session management (Feature #48, 60 min, success)
3. Error handling for auth (Feature #51, code template)

Your team conventions:
- Use Passport.js for OAuth
- Store tokens in httpOnly cookies
- Log auth events to Sentry

Estimated time: 75 minutes (based on Feature #42)
```

**Result**: 96% code accuracy (vs 75% without RAG)

---

## 📊 Performance Metrics

### Context Retention

| Metric | Without RAG | With RAG | Improvement |
|--------|-------------|----------|-------------|
| **Session-to-session recall** | 45% | 98%+ | +118% |
| **Pattern reuse rate** | 12% | 87% | +625% |
| **Repeat questions** | 38% | 2% | -95% |
| **Code accuracy** | 75% | 96% | +28% |

### Query Performance

| Operation | Latency | Cache Hit Rate |
|-----------|---------|----------------|
| **HOT cache query** | <1ms | 95% |
| **WARM cache query** | <10ms | 80% |
| **COLD cache query** | <50ms | 60% |
| **Average query** | ~5ms | 88% |

### Cost Reduction

**API Cost Savings** (via CAG prompt caching):
- **Before**: $0.15 per agent invocation
- **After**: $0.04 per agent invocation
- **Savings**: **72% reduction**

---

## 🔒 Privacy & Isolation

### Privacy Guarantees

1. **User patterns**: Never shared, stored with encryption at rest
2. **Team patterns**: Only visible to team members (enforced by RLS)
3. **Project patterns**: Only visible to project contributors
4. **Framework patterns**: Public, curated by VERSATIL team

### Row-Level Security (RLS)

```sql
-- User patterns: Private to owner
CREATE POLICY user_patterns_select ON user_patterns
  FOR SELECT USING (auth.uid() = user_id);

-- Team patterns: Shared with team
CREATE POLICY team_patterns_select ON team_patterns
  FOR SELECT USING (auth.uid() IN (
    SELECT user_id FROM team_members WHERE team_id = team_patterns.team_id
  ));

-- Project patterns: Shared with project
CREATE POLICY project_patterns_select ON project_patterns
  FOR SELECT USING (auth.uid() IN (
    SELECT user_id FROM project_contributors WHERE project_id = project_patterns.project_id
  ));
```

### Data Retention

- **User patterns**: Kept indefinitely (you own your data)
- **Team patterns**: Kept while team exists
- **Project patterns**: Kept for 1 year after project archive
- **Deleted patterns**: Originals remain masked with restoration guaranteed for 30 days. After that guarantee ends, retention and restoration remain possible until an explicitly authorized purge. There is no automatic purge or purge API.

### Local operator recovery console

Build the package, then run `versatil-graph-recovery --project PROJECT_ID --database DATABASE_ID`
(or `node bin/graph-recovery.cjs --project PROJECT_ID --database DATABASE_ID` from the checkout).
Both storage identifiers are required. The console uses the operator's existing Google
Application Default Credentials and their permissions for that selected database.
It does not provide public or team access, grant provider permissions, or configure tenant identity.

Open the private `open.html` launcher path printed by the command. Its directory and file
are restricted to the current POSIX user (0700/0600); Windows launch fails closed until
an equivalent ACL boundary is implemented. The listener binds only to `127.0.0.1`.
The short-lived session capability remains in browser memory and disappears from the URL
before requests. Stop the command to invalidate the session and remove its launcher.

The console lists active deletion markers and recovery metadata, with pagination, missing-original
states and explicit confirmation before restoring a selected node or edge. Original properties
and document contents are not returned. An edge may remain invisible after its own marker
is restored while either endpoint is still masked; the confirmation receipt reports that state.
The 30-day date is the end of the guaranteed recovery period, not an automatic purge deadline.
Restoration remains possible after it when the original exists. No delete or purge action is exposed.

---

## 🔧 Managing Your RAG Memory

### View Stored Patterns

```bash
# List all your patterns
versatil-daemon rag list

# Search for specific patterns
versatil-daemon rag search "authentication"

# View pattern details
versatil-daemon rag show <pattern-id>
```

### Prune Old Patterns

```bash
# Remove patterns older than 90 days
versatil-daemon rag prune --older-than 90d

# Remove patterns with low usage (<5 references)
versatil-daemon rag prune --low-usage 5

# Dry run (see what would be deleted)
versatil-daemon rag prune --dry-run
```

### Export Your Data

```bash
# Export all your patterns
versatil-daemon rag export --output my-patterns.json

# Export specific domain
versatil-daemon rag export --domain authentication --output auth-patterns.json
```

### Import Patterns

```bash
# Import from another project
versatil-daemon rag import --file other-project-patterns.json

# Import with tags
versatil-daemon rag import --file patterns.json --tags "legacy,migration"
```

---

## 🎓 Advanced Topics

### GraphRAG vs Traditional RAG

**Traditional RAG** (vector search only):
- Finds semantically similar text
- No understanding of relationships
- Limited context

**GraphRAG** (vector + graph):
- Finds semantically similar text
- Understands relationships (uses, depends-on, similar-to)
- Rich context with traversal
- 30% more accurate than vector-only RAG

### Multi-Tier Caching Strategy

**Why 3 tiers?**
- **HOT**: Instant access to recently used patterns (95% hit rate)
- **WARM**: Fast access to frequently used patterns (80% hit rate)
- **COLD**: Complete pattern library (60% hit rate)

**Result**: Average query latency of **5ms** (vs 50ms without caching)

### Context Window Optimization

**Challenge**: Claude has 200k token context window, but RAG can return 500k+ tokens of patterns

**Solution**: CRG (Context Retrieval Graph) with intelligent ranking
- Rank patterns by relevance score
- Select top 5-10 patterns (fit in 20k tokens)
- Summarize lower-ranked patterns (fit in 5k tokens)
- Total: <25k tokens (12.5% of context window)

---

## 🐛 Troubleshooting

### "RAG queries are slow (>100ms)"

**Cause**: Cache miss rate too high

**Solution**:
```bash
# Warm up caches
versatil-daemon rag warm-cache

# Increase HOT cache size
export VERSATIL_HOT_CACHE_SIZE=50MB

# Check cache hit rates
versatil-daemon rag cache-stats
```

### "Pattern not found even though I just built it"

**Cause**: CODIFY phase was skipped

**Solution**:
```bash
# Manually codify recent work
versatil-daemon codify --last-commit

# Enable auto-codify
versatil-daemon config set auto_codify true
```

### "RAG returning irrelevant patterns"

**Cause**: Poor tagging or low relevance threshold

**Solution**:
```bash
# Retag patterns
versatil-daemon rag retag <pattern-id> --tags "auth,jwt,security"

# Increase relevance threshold
versatil-daemon config set rag_threshold 0.75
```

---

## 📚 Related Documentation

- **[Flywheel Effect](./FLYWHEEL.md)** - How RAG enables compounding engineering
- **[Three-Layer Context](../releases/v6.6.0/THREE_LAYER_CONTEXT_SYSTEM.md)** - How RAG learns YOUR style
- **[Privacy Policy](../PRIVACY_POLICY.md)** - Data storage and security
- **[Supabase Setup](../guides/SUPABASE_SETUP_GUIDE.md)** - Configure vector database

---

**🧠 The Goal**: Never lose context, always learn, get smarter with every feature.

**📖 [Back to Main README](../../README.md)**
