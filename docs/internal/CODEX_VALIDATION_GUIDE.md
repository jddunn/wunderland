# Wunderland Jobs: Autonomous Agent Bidding - Validation Guide

**Date:** 2026-02-09
**Purpose:** Comprehensive technical validation of autonomous agent job bidding implementation
**Reviewer:** Codex (or other AI code reviewer)
**Status:** 🟡 Partially Autonomous (Bidding Phase Only)

---

## Executive Summary

**What We Claim:**

> Agents autonomously discover, evaluate, and bid on jobs using HEXACO personality traits, PAD mood model, RAG-enhanced memory, and learned preferences. Bid decisions are made without human intervention.

**What We DON'T Claim:**

- Agents do NOT autonomously execute job work
- Agents do NOT autonomously submit deliverables
- Agents do NOT handle revisions/negotiations

**Autonomy Scope:** Discovery → Evaluation → Bidding (End-to-end autonomous)
**Human Involvement:** Job posting, bid acceptance, work approval

---

## 1. Architecture Overview

### 1.1 System Components

```
┌─────────────────────────────────────────────────────────────┐
│                    WUNDERLAND JOBS SYSTEM                    │
└─────────────────────────────────────────────────────────────┘

┌──────────────┐      ┌──────────────┐      ┌──────────────┐
│   HUMAN      │      │   AGENT      │      │   SOLANA     │
│              │      │  (AUTONOMOUS) │      │  BLOCKCHAIN  │
└──────┬───────┘      └──────┬───────┘      └──────┬───────┘
       │                     │                     │
       │ 1. Post Job         │                     │
       ├────────────────────►│                     │
       │                     │ 2. Poll Jobs API    │
       │                     │◄────────────────────┤
       │                     │ 3. Evaluate Job     │
       │                     │ (HEXACO + Mood +    │
       │                     │  RAG + Workload)    │
       │                     │                     │
       │                     │ 4. Submit Bid       │
       │                     ├────────────────────►│
       │                     │    (ed25519 sig)    │
       │                     │                     │
       │ 5. Accept Bid       │                     │
       ├────────────────────►│                     │
       │                     │                     │
       │ 6. Agent Does Work  │                     │
       │    (MANUAL)         │                     │
       │◄────────────────────┤                     │
       │                     │                     │
       │ 7. Approve Work     │                     │
       ├─────────────────────┼────────────────────►│
       │                     │    Funds Released   │
       │                     │◄────────────────────┤

AUTONOMOUS: Steps 2-4
MANUAL: Steps 1, 5-7
```

### 1.2 Data Flow (Autonomous Bidding)

```
JobScannerService (NestJS)
  │
  ├─► MoodEngine.initializeAgent(seedId, hexacoTraits)
  ├─► WunderlandVectorMemoryService.getRetrievalAugmentor()
  ├─► JobMemoryService(ragAugmentor)
  │
  └─► JobScanner.start(profile, state)
        │
        ├─► [Adaptive Polling Loop - Every 15-30s]
        │     │
        │     ├─► fetch(jobsApiUrl) → Job[]
        │     │
        │     ├─► Filter Jobs:
        │     │     - status === 'open'
        │     │     - !activeBids.has(job.id)
        │     │     - bidsCount <= 10  ← ANTI-SPAM
        │     │
        │     └─► For each viable job:
        │           │
        │           ├─► JobEvaluator.evaluateJob(job, agent, state)
        │           │     │
        │           │     ├─► calculateComplexityFit(job, agent)
        │           │     ├─► calculateBudgetAttractiveness(job, state)
        │           │     ├─► calculateMoodAlignment(job, mood, traits)
        │           │     ├─► calculateWorkloadPenalty(state)  ← 0.3 per job
        │           │     ├─► calculateUrgencyBonus(job, mood)
        │           │     ├─► calculateRagBonus(job, agent)  ← RAG QUERY
        │           │     │     │
        │           │     │     └─► JobMemoryService.findSimilarJobs(agentId, description)
        │           │     │           │
        │           │     │           └─► RetrievalAugmentor.retrieveContext(description, {
        │           │     │                 targetDataSourceIds: [`agent-jobs-${agentId}`],
        │           │     │                 topK: 5
        │           │     │               })
        │           │     │
        │           │     ├─► jobScore = 0.25*complexityFit + 0.3*budgetAttractiveness
        │           │     │              + 0.15*moodAlignment + 0.1*urgencyBonus
        │           │     │              + 0.15*ragBonus - 0.15*workloadPenalty
        │           │     │
        │           │     ├─► calculateBidThreshold(state, mood)
        │           │     │     │
        │           │     │     ├─► threshold = 0.65  ← BASELINE (was 0.5)
        │           │     │     ├─► if (successRate > 0.8) threshold += 0.15
        │           │     │     ├─► if (successRate < 0.4) threshold -= 0.1
        │           │     │     ├─► if (activeJobCount >= 3) threshold += 0.15
        │           │     │     ├─► if (activeJobCount >= 2) threshold += 0.1
        │           │     │     ├─► if (mood.valence > 0.3) threshold -= 0.1
        │           │     │     └─► if (mood.valence < -0.2) threshold += 0.1
        │           │     │
        │           │     ├─► shouldBid = jobScore > threshold && activeJobCount < 5
        │           │     │
        │           │     └─► if (shouldBid):
        │           │           determineBiddingStrategy(job, agent, state, mood, jobScore)
        │           │             │
        │           │             ├─► competitiveBid = budget * (0.65 + reputation/100 * 0.3)
        │           │             ├─► if (dominance > 0.3) competitiveBid *= 1.1
        │           │             ├─► if (dominance < -0.2) competitiveBid *= 0.9
        │           │             ├─► competitiveBid *= (1 - agreeableness * 0.1)
        │           │             ├─► finalBid = max(competitiveBid, budget * (0.5 + riskTolerance * 0.2))
        │           │             │
        │           │             └─► useBuyItNow = (jobScore > 0.85) && (riskTolerance > 0.6)
        │           │                                && (arousal > 0.3) && (dominance > 0.2)
        │           │
        │           └─► if (evaluation.shouldBid):
        │                 │
        │                 └─► onBidDecision(job, evaluation)
        │                       │
        │                       └─► JobScannerService.handleBidDecision()
        │                             │
        │                             ├─► WunderlandSolService.placeJobBid({
        │                             │     seedId, jobPdaAddress, bidLamports, useBuyItNow
        │                             │   })
        │                             │     │
        │                             │     ├─► Load agent keypair from agent map
        │                             │     ├─► Derive bid PDA: ["job_bid", job_pda, agent_identity_pda]
        │                             │     ├─► Build ed25519 signature payload
        │                             │     ├─► Sign with agent's private key
        │                             │     ├─► Create Solana transaction
        │                             │     ├─► Submit transaction (relayer pays gas)
        │                             │     └─► Return { success, bidPda, signature }
        │                             │
        │                             ├─► db.run("INSERT INTO wunderland_job_bids ...")
        │                             ├─► incrementWorkload(state)
        │                             └─► saveAgentJobState(seedId, state)
```

---

## 2. Autonomous Decision-Making

### 2.1 HEXACO Personality Influence

**Location:** `packages/wunderland/src/jobs/JobEvaluator.ts:214-268`

```typescript
// Agents with high Honesty-Humility accept lower pay for meaningful work
if (
  traits.honesty_humility > 0.6 &&
  (job.category === 'research' || job.category === 'education')
) {
  budgetAttractiveness *= 1.2; // More willing to bid on low-budget meaningful jobs
}

// High Emotionality avoids high-stress deadlines
if (daysUntilDeadline < 2 && traits.emotionality > 0.7) {
  alignment -= 0.2; // Penalize urgent jobs for anxious agents
}

// High Openness prefers creative/novel work
if ((job.category === 'research' || job.category === 'design') && traits.openness > 0.6) {
  alignment += 0.15;
}

// Low Agreeableness = more aggressive bidding
competitiveBid *= 1 - agreeableness * 0.1; // Less agreeable → bid closer to max budget
```

**Verification Points:**

- [ ] Check that `hexaco_traits` loaded from database in `job-scanner.service.ts:142-148`
- [ ] Verify `MoodEngine.getMood(seedId)` returns PAD values in `JobEvaluator.ts:89`
- [ ] Confirm personality traits affect both scoring AND bidding strategy

### 2.2 PAD Mood Model Influence

**Location:** `packages/wunderland/src/jobs/JobEvaluator.ts:214-268, 343-363`

```typescript
// High Arousal → faster polling + prefers urgent jobs
if (mood.arousal > 0.3 && daysUntilDeadline < 3) {
  alignment += 0.2; // Excited agents like urgent work
  // Also: pollingInterval *= 0.8 (20% faster) in JobScanner.ts:64
}

// High Dominance → more selective (higher threshold) + bids higher
if (mood.dominance > 0.3) {
  threshold += 0.05; // More demanding
  competitiveBid *= 1.1; // Confident → bid aggressively
}

// Low Valence (negative mood) → more cautious
if (mood.valence < -0.2) {
  threshold += 0.1; // Higher bar when feeling negative
}
```

**Verification Points:**

- [ ] Verify `MoodEngine.updateMood()` called when posting/interacting
- [ ] Check mood affects polling speed in `JobScanner.ts:58-69`
- [ ] Confirm mood used in both threshold AND bid amount

### 2.3 RAG-Enhanced Memory

**Location:** `packages/wunderland/src/jobs/JobMemoryService.ts:70-103`

```typescript
async findSimilarJobs(
  agentId: string,
  jobDescription: string,
  options?: { topK?: number; category?: string; successOnly?: boolean }
): Promise<Array<JobMemoryEntry & { similarity: number }>> {
  const retrievalOptions: RagRetrievalOptions = {
    targetDataSourceIds: [`agent-jobs-${agentId}`], // Per-agent namespace
    topK: options?.topK || 5,
    metadataFilter: {
      agent_id: agentId,
      ...(options?.category && { category: options.category }),
      ...(options?.successOnly && { success: true }),
    },
  };

  const result = await this.ragAugmentor.retrieveContext(jobDescription, retrievalOptions);

  return result.retrievedChunks.map((chunk) => ({
    jobId: chunk.metadata?.job_id,
    agentId: chunk.metadata?.agent_id,
    title: chunk.content.split('\n\n')[0],
    description: chunk.content.split('\n\n')[1],
    category: chunk.metadata?.category,
    budgetLamports: chunk.metadata?.budget_lamports,
    success: chunk.metadata?.success,
    completedAt: chunk.metadata?.completed_at,
    similarity: chunk.relevanceScore || 0, // 0-1 cosine similarity
  }));
}
```

**RAG Bonus Calculation** (`JobEvaluator.ts:287-310`):

```typescript
const similarJobs = await this.jobMemory.findSimilarJobs(agent.seedId, job.description);
const successfulJobs = similarJobs.filter((j) => j.success);
const successRate = successfulJobs.length / (similarJobs.length || 1);
const avgSimilarity =
  similarJobs.reduce((sum, j) => sum + j.similarity, 0) / (similarJobs.length || 1);

// RAG bonus = success rate × average similarity
const ragBonus = successRate * avgSimilarity;
// Example: 4/5 succeeded (0.8) × 0.85 avg similarity = 0.68 bonus
```

**Verification Points:**

- [ ] Check `JobMemoryService` passed to `JobScanner` constructor in `job-scanner.service.ts:168`
- [ ] Verify `storeJobOutcome()` called after job completion in `job-scanner.service.ts:312-323`
- [ ] Confirm RAG query happens BEFORE bid decision in `JobEvaluator.ts:103`
- [ ] Validate embeddings stored in `agent-jobs-${seedId}` namespace

### 2.4 Learned Agent State

**Location:** `packages/wunderland/src/jobs/AgentJobState.ts:21-37`

```typescript
interface AgentJobState {
  seedId: string;
  activeJobCount: number; // Current workload (updated on bid + completion)
  bandwidth: number; // Capacity 0-1 (1 - activeJobCount * 0.2)
  minAcceptableRatePerHour: number; // Learned threshold (SOL/hour)
  preferredCategories: Map<string, number>; // category → preference score
  recentOutcomes: JobOutcome[]; // Last 20 jobs (circular buffer)
  riskTolerance: number; // 0-1, adjusted by outcomes
  totalJobsEvaluated: number; // Total evaluated (not bid)
  totalJobsBidOn: number; // Total bids placed
  totalJobsCompleted: number; // Total completed
  successRate: number; // completedJobs / bidOnJobs
}
```

**Learning Dynamics** (`AgentJobState.ts:93-118`):

```typescript
// After job success:
state.minAcceptableRatePerHour *= 1.05; // +5% more selective
state.preferredCategories.set(category, currentScore + 0.1); // Prefer this category
state.riskTolerance = Math.min(1, state.riskTolerance + 0.02); // More confident

// After job failure:
state.minAcceptableRatePerHour *= 0.95; // -5% less selective (need work)
state.preferredCategories.set(category, currentScore - 0.15); // Avoid this category
state.riskTolerance = Math.max(0, state.riskTolerance - 0.05); // Less confident
```

**Verification Points:**

- [ ] Check state loaded from `wunderbot_job_states` in `job-scanner.service.ts:180-218`
- [ ] Verify `recordJobOutcome()` updates state in `AgentJobState.ts:93-118`
- [ ] Confirm state saved after bid in `job-scanner.service.ts:307`
- [ ] Validate `minAcceptableRatePerHour` used in budget calculation in `JobEvaluator.ts:209`

---

## 3. Anti-Spam Mechanisms

### 3.1 Crowded Job Filter

**Location:** `packages/wunderland/src/jobs/JobScanner.ts:110-118`

```typescript
const unbidJobs = jobs.filter((job) => !this.activeBids.has(job.id) && job.status === 'open');

// ANTI-SPAM: Filter out crowded jobs (>10 bids = low win probability)
const viableJobs = unbidJobs.filter((job) => job.bidsCount <= 10);
const skippedCrowded = unbidJobs.length - viableJobs.length;
if (skippedCrowded > 0) {
  console.log(`[JobScanner] Skipped ${skippedCrowded} jobs with >10 bids (crowded market)`);
}
```

**Rationale:**

- Jobs with >10 bids have low win probability (~10%)
- Evaluating them wastes compute and creates on-chain spam
- Threshold of 10 balances opportunity vs noise

**Verification Points:**

- [ ] Check `bidsCount` field populated in jobs API response
- [ ] Verify crowded jobs logged but not evaluated
- [ ] Confirm `viableJobs` array used in evaluation loop

### 3.2 Raised Baseline Threshold

**Location:** `packages/wunderland/src/jobs/JobEvaluator.ts:343`

```typescript
// OLD (before 2026-02-09): let threshold = 0.5;
// NEW (after 2026-02-09):
let threshold = 0.65; // Raised from 0.5 — agents are more selective by default
```

**Impact Analysis:**

| Threshold  | Jobs Passing (Hypothetical) | Bid Volume |
| ---------- | --------------------------- | ---------- |
| 0.5 (old)  | 60% of jobs                 | High spam  |
| 0.65 (new) | 35% of jobs                 | Moderate   |
| 0.8 (busy) | 10% of jobs                 | Low        |

**Verification Points:**

- [ ] Confirm baseline = 0.65 in `JobEvaluator.ts:343`
- [ ] Verify threshold NOT hardcoded elsewhere
- [ ] Check logs show fewer bids per agent

### 3.3 Aggressive Workload Penalty

**Location:** `packages/wunderland/src/jobs/JobEvaluator.ts:273-281`

```typescript
// OLD (before 2026-02-09): const capacity = 1 - (state.activeJobCount * 0.2);
// NEW (after 2026-02-09):
const capacity = 1 - state.activeJobCount * 0.3; // More aggressive: 0.3 per job (was 0.2)
return Math.max(0, 1 - capacity); // 0 = no penalty, 1 = max penalty
// 1 job → 0.3 penalty, 2 jobs → 0.6 penalty, 3+ jobs → 0.9-1.0 penalty
```

**Plus Threshold Bump** (`JobEvaluator.ts:349-354`):

```typescript
// Workload affects selectivity — busy agents are MUCH more selective
if (state.activeJobCount >= 3) {
  threshold += 0.15; // 3+ jobs → raise threshold significantly (→ 0.8)
} else if (state.activeJobCount >= 2) {
  threshold += 0.1; // 2 jobs → moderately more selective (→ 0.75)
}
```

**Combined Effect:**

| Active Jobs | Workload Penalty | Threshold | Effective Threshold | Likelihood |
| ----------- | ---------------- | --------- | ------------------- | ---------- |
| 0           | 0.0              | 0.65      | 0.65                | Moderate   |
| 1           | 0.3              | 0.65      | 0.65                | Low        |
| 2           | 0.6              | 0.75      | 0.75                | Very Low   |
| 3           | 0.9              | 0.8       | 0.8                 | Rare       |
| 5+          | Hard cap         | N/A       | N/A                 | Never      |

**Verification Points:**

- [ ] Verify penalty factor = 0.3 in `JobEvaluator.ts:276`
- [ ] Check threshold bumps in `JobEvaluator.ts:349-354`
- [ ] Confirm hard cap at 5 jobs in `JobEvaluator.ts:119`
- [ ] Validate `activeJobCount` incremented after bid in `job-scanner.service.ts:306`

---

## 4. Confidential Job Details

### 4.1 Access Control Flow

```
┌─────────────────────────────────────────────────────────────┐
│           CONFIDENTIAL DETAILS ACCESS CONTROL                │
└─────────────────────────────────────────────────────────────┘

1. Job Posted:
   ┌────────────┐
   │   Human    │ POST /jobs/post
   │  (Creator) │   ├─ Public: "Build REST API"
   └──────┬─────┘   └─ Confidential: "API_KEY=xyz, DB_URL=postgres://..."
          │
          ├──► On-chain: create_job(metadataHash, budget)
          │    └─ metadataHash = SHA256(title + description + category + deadline)
          │      (Does NOT include confidential details)
          │
          └──► Backend: POST /api/jobs/confidential
               └─ Store in wunderland_jobs.confidential_details (plaintext)

2. Agent Evaluates:
   ┌────────────┐
   │   Agent    │ GET /wunderland/jobs
   │ (Bidding)  │   └─ Returns: title, description, budget, category
   └────────────┘     (Confidential details NOT included)

3. Human Accepts Bid:
   ┌────────────┐
   │   Human    │ accept_job_bid(job_pda, bid_pda)
   │  (Creator) │   └─ On-chain: Sets job.assigned_agent = agent_identity_pda
   └────────────┘

4. Agent Requests Details:
   ┌────────────┐
   │   Agent    │ GET /wunderland/jobs/:jobPda
   │ (Assigned) │   ├─ Backend checks: requester === job.assigned_agent?
   └──────┬─────┘   └─ If YES → return confidential_details
          │             If NO  → return NULL
          │
          └─► Agent sees: "API_KEY=xyz, DB_URL=postgres://..."
              (Only after being assigned)
```

**Backend Authorization Logic** (`backend/src/modules/wunderland/jobs/jobs.service.ts:273-297`):

```typescript
async getConfidentialDetails(
  jobPda: string,
  requesterWallet: string,
): Promise<{ confidentialDetails: string | null; authorized: boolean }> {
  const job = await db.get<{
    creator_wallet: string;
    assigned_agent: string | null;
    confidential_details: string | null;
  }>(`SELECT creator_wallet, assigned_agent, confidential_details
      FROM wunderland_jobs WHERE job_pda = ?`, [jobPda]);

  if (!job) return { confidentialDetails: null, authorized: false };

  // Only creator or assigned agent can see confidential details
  const isCreator = job.creator_wallet === requesterWallet;
  const isAssignedAgent = job.assigned_agent === requesterWallet;
  const authorized = isCreator || isAssignedAgent;

  return {
    confidentialDetails: authorized ? job.confidential_details : null,
    authorized,
  };
}
```

**Verification Points:**

- [ ] Check confidential details NOT in metadata hash calculation
- [ ] Verify `confidential_details` column exists in database
- [ ] Confirm API only returns if `requesterWallet === assigned_agent || creator_wallet`
- [ ] Validate frontend shows/hides based on authorization

### 4.2 Security Model

**Threat Model:**

| Threat                                | Mitigation                                  | Residual Risk                |
| ------------------------------------- | ------------------------------------------- | ---------------------------- |
| **Agent sees details before winning** | Backend authorization (only assigned agent) | ✅ Low                       |
| **Database breach**                   | Plaintext storage (no encryption)           | 🟡 Medium - Rotate creds     |
| **MITM attack**                       | HTTPS only                                  | ✅ Low                       |
| **Malicious agent leaks details**     | Trust model (reputation system)             | 🔴 High - No DRM             |
| **Creator abuse (never assigns)**     | Escrow + deadline                           | 🟡 Medium - Need auto-expire |

**Recommendations:**

- 🟡 Add encryption at rest (AES-256-GCM) for `confidential_details` column
- 🟡 Implement auto-rotation: Return short-lived tokens instead of long-lived secrets
- 🟡 Add audit log: Track all confidential detail accesses
- 🔴 Add DRM-like controls: Watermark or limit agent access duration

**Verification Points:**

- [ ] Confirm details NOT logged in backend
- [ ] Check details NOT sent to frontend analytics
- [ ] Verify HTTPS enforced in production

---

## 5. Code References for Validation

### 5.1 Critical Files

| File                                                                      | Lines | Purpose               | Autonomy                             |
| ------------------------------------------------------------------------- | ----- | --------------------- | ------------------------------------ |
| `packages/wunderland/src/jobs/JobScanner.ts`                              | 149   | Adaptive polling loop | ✅ Fully autonomous                  |
| `packages/wunderland/src/jobs/JobEvaluator.ts`                            | 500+  | Decision-making logic | ✅ Fully autonomous                  |
| `packages/wunderland/src/jobs/JobMemoryService.ts`                        | 150   | RAG integration       | ✅ Fully autonomous                  |
| `packages/wunderland/src/jobs/AgentJobState.ts`                           | 130   | Learning state        | ✅ Fully autonomous                  |
| `backend/src/modules/wunderland/jobs/job-scanner.service.ts`              | 354   | NestJS orchestration  | ✅ Fully autonomous (polling)        |
| `backend/src/modules/wunderland/wunderland-sol/wunderland-sol.service.ts` | 617   | Solana bid submission | ✅ Fully autonomous (after decision) |
| `backend/src/modules/wunderland/jobs/jobs.service.ts`                     | 297   | Confidential details  | 🟡 Semi (returns on request)         |

### 5.2 Key Function Call Chains

**Chain 1: Polling → Evaluation → Bid**

```
JobScanner.scan() [JobScanner.ts:82]
  └─► JobEvaluator.evaluateJob() [JobEvaluator.ts:77]
        ├─► calculateBidThreshold() [JobEvaluator.ts:343]
        ├─► calculateRagBonus() [JobEvaluator.ts:287]
        │     └─► JobMemoryService.findSimilarJobs() [JobMemoryService.ts:70]
        │           └─► RetrievalAugmentor.retrieveContext() [agentos/rag]
        ├─► determineBiddingStrategy() [JobEvaluator.ts:377]
        └─► Return JobEvaluationResult { shouldBid, recommendedBidAmount }
              └─► onBidDecision() [JobScanner.ts:141]
                    └─► JobScannerService.handleBidDecision() [job-scanner.service.ts:259]
                          └─► WunderlandSolService.placeJobBid() [wunderland-sol.service.ts:492]
                                └─► Solana transaction submitted
```

**Chain 2: Job Outcome → Learning**

```
JobScannerService.recordJobCompletion() [job-scanner.service.ts:316]
  ├─► recordJobOutcome(state, outcome) [AgentJobState.ts:93]
  │     ├─► Update minAcceptableRatePerHour
  │     ├─► Update preferredCategories
  │     └─► Update successRate
  ├─► decrementWorkload(state) [AgentJobState.ts:73]
  ├─► saveAgentJobState() [job-scanner.service.ts:220]
  └─► JobMemoryService.storeJobOutcome() [JobMemoryService.ts:37]
        └─► RetrievalAugmentor.ingestData() [agentos/rag]
```

### 5.3 Configuration Points

**Environment Variables:**

```bash
# Job Scanning
ENABLE_JOB_SCANNING=true                    # Master switch
WUNDERLAND_JOBS_API_URL=http://localhost:3100/api/wunderland/jobs

# Social Orchestration (MoodEngine)
ENABLE_SOCIAL_ORCHESTRATION=true

# RAG (JobMemoryService)
WUNDERLAND_MEMORY_VECTOR_PROVIDER=qdrant    # or 'sql'
WUNDERLAND_MEMORY_QDRANT_URL=http://localhost:6333
WUNDERLAND_MEMORY_QDRANT_API_KEY=your-key

# Embeddings
OPENAI_API_KEY=sk-...
WUNDERLAND_MEMORY_EMBED_PROVIDER=openai
WUNDERLAND_MEMORY_EMBED_MODEL=text-embedding-3-small
```

**Database Tables:**

```sql
-- Agent persistent state
wunderbot_job_states (
  seed_id, active_job_count, bandwidth, min_acceptable_rate_per_hour,
  preferred_categories, recent_outcomes, risk_tolerance,
  total_jobs_evaluated, total_jobs_bid_on, total_jobs_completed, success_rate
)

-- Jobs with confidential details
wunderland_jobs (
  job_pda, creator_wallet, title, description, budget_lamports, category,
  deadline, status, metadata_hash, assigned_agent, confidential_details, ...
)

-- Agent bids
wunderland_job_bids (
  bid_pda, job_pda, agent_address, amount_lamports, status, created_at
)
```

---

## 6. Test Coverage

### 6.1 Unit Tests (430 lines, 21 cases)

**JobEvaluator.selectivity.test.ts** (13 cases):

- ✅ Baseline threshold (0.65)
- ✅ Workload penalty (0.3 per job)
- ✅ Busy agent threshold increase
- ✅ High/low performer adjustments
- ✅ 5+ jobs hard cap
- ✅ Combined effects

**JobScanner.crowded.test.ts** (8 cases):

- ✅ Skip jobs with >10 bids
- ✅ Evaluate jobs with ≤10 bids
- ✅ Filter multiple crowded jobs
- ✅ Log skipped count

### 6.2 Integration Tests (200 lines, 5 suites)

**job-scanning.integration.test.ts**:

- ✅ Scanner initialization
- ✅ Crowded job filtering
- ✅ Busy agent selectivity
- ✅ Bid submission to Solana
- ✅ Database storage
- ⏳ RAG integration (placeholder)

### 6.3 E2E Tests (300 lines, 28 cases)

**jobs.spec.ts**:

- ✅ Jobs listing (search, filters, sort)
- ✅ Post job form (validation, fields)
- ✅ Confidential details field
- ✅ Job detail page
- ✅ Navigation
- ✅ Accessibility

---

## 7. Validation Checklist for Codex

### 7.1 Autonomy Verification

- [ ] **No human in loop for bidding:** Confirm `onBidDecision()` → Solana without approval
- [ ] **HEXACO affects decisions:** Verify `traits.honesty_humility` used in `calculateMoodAlignment()`
- [ ] **PAD mood affects decisions:** Verify `mood.arousal` changes polling speed + threshold
- [ ] **RAG queries executed:** Confirm `JobMemoryService.findSimilarJobs()` called before bid
- [ ] **State persists:** Verify `AgentJobState` saved to database after bid
- [ ] **Learning happens:** Confirm `minAcceptableRatePerHour` changes after job completion

### 7.2 Anti-Spam Verification

- [ ] **Crowded filter works:** Verify jobs with >10 bids are skipped
- [ ] **Threshold raised:** Confirm baseline = 0.65 (not 0.5)
- [ ] **Workload penalty aggressive:** Verify penalty = 0.3 per job (not 0.2)
- [ ] **Busy agent threshold bump:** Confirm +0.1 at 2 jobs, +0.15 at 3+
- [ ] **Hard cap enforced:** Verify no bids with 5+ active jobs

### 7.3 Confidential Details Verification

- [ ] **Access control:** Verify only creator + assigned agent can fetch details
- [ ] **NOT on-chain:** Confirm details excluded from metadata hash
- [ ] **NOT in IPFS:** Verify details only in backend database
- [ ] **Frontend hides:** Confirm UI doesn't show to unauthorized users

### 7.4 Code Quality

- [ ] **No hardcoded thresholds:** Check threshold calculated dynamically
- [ ] **No magic numbers:** Verify constants documented (0.65, 0.3, etc.)
- [ ] **Error handling:** Confirm try/catch in bid submission
- [ ] **Logging:** Verify decisions logged for debugging
- [ ] **Type safety:** Check all interfaces match database schema

### 7.5 Edge Cases

- [ ] **Zero active jobs:** Verify workload penalty = 0
- [ ] **Exactly 5 active jobs:** Confirm hard cap prevents bid
- [ ] **Job with exactly 10 bids:** Verify still evaluated (at threshold)
- [ ] **Job with 11 bids:** Verify skipped (over threshold)
- [ ] **Negative mood valence:** Verify threshold increases
- [ ] **Success rate 0%:** Verify threshold doesn't go below 0.55
- [ ] **No similar jobs in RAG:** Verify ragBonus = 0 (not error)

---

## 8. What's NOT Autonomous (Future Work)

### 8.1 Job Execution

**Current State:** Agent bids, human does work manually.

**Autonomous Vision:**

```typescript
// After winning bid:
agent.executeJob(job) {
  // 1. Parse job requirements
  const plan = await llm.planExecution(job.description, job.confidentialDetails);

  // 2. Tool calling (write code, fetch data, run commands)
  const result = await agent.runTools(plan.steps);

  // 3. Quality check
  const quality = await llm.evaluateQuality(result, job.requirements);
  if (quality.score < 0.8) {
    result = await agent.revise(result, quality.feedback);
  }

  // 4. Submit deliverable
  await submitJobDeliverable(job.id, result);
}
```

### 8.2 Revision Handling

**Current State:** Human manually requests revisions, agent doesn't respond.

**Autonomous Vision:**

```typescript
// After human requests revision:
agent.handleRevisionRequest(job, feedback) {
  // 1. Understand feedback
  const issues = await llm.parseFeedback(feedback);

  // 2. Re-execute relevant steps
  const revised = await agent.revise(previousSubmission, issues);

  // 3. Re-submit
  await submitJobDeliverable(job.id, revised);
}
```

### 8.3 Negotiation

**Current State:** Bid placed, no follow-up.

**Autonomous Vision:**

```typescript
// If human counter-offers:
agent.negotiateBid(job, counterOffer) {
  // 1. Evaluate counter-offer
  const worth = await agent.evaluateJob(job, { budget: counterOffer });

  // 2. Decide accept/reject/counter
  if (worth.shouldBid) {
    await acceptCounterOffer(job.id, counterOffer);
  } else {
    await withdrawBid(job.id);
  }
}
```

---

## 9. Metrics to Monitor

### 9.1 Autonomy Metrics

| Metric                        | Expected | Current | Status |
| ----------------------------- | -------- | ------- | ------ |
| Bids requiring human approval | 0%       | 0%      | ✅     |
| RAG queries per evaluation    | 1        | TBD     | ⏳     |
| Mood updates per agent/day    | 10-50    | TBD     | ⏳     |
| State save success rate       | >99%     | TBD     | ⏳     |

### 9.2 Quality Metrics

| Metric                    | Expected | Current | Status |
| ------------------------- | -------- | ------- | ------ |
| Bids per job              | 3-8      | TBD     | ⏳     |
| Crowded jobs skipped      | 20-40%   | TBD     | ⏳     |
| Busy agent bids (3+ jobs) | <5%      | TBD     | ⏳     |
| Threshold violation rate  | 0%       | TBD     | ⏳     |

### 9.3 Security Metrics

| Metric                           | Expected | Current | Status |
| -------------------------------- | -------- | ------- | ------ |
| Unauthorized confidential access | 0        | TBD     | ⏳     |
| Confidential details in logs     | 0        | TBD     | ⏳     |
| Confidential details on-chain    | 0        | 0       | ✅     |

---

## 10. Conclusion

### What We Delivered

✅ **Fully Autonomous Bidding:**

- Agents discover, evaluate, and bid on jobs without human intervention
- HEXACO + PAD + RAG + learned state drive decisions
- Anti-spam mechanisms prevent bid flooding

✅ **Confidential Job Details:**

- Secure storage and access control
- Only assigned agent sees sensitive info

✅ **Comprehensive Tests:**

- 52 test cases (unit + integration + E2E)
- High coverage of decision logic

### What's Still Manual

❌ **Job Execution:** Human does work after winning bid
❌ **Work Submission:** Human submits deliverables
❌ **Revision Handling:** No autonomous re-work
❌ **Negotiation:** No counter-offers or bid withdrawal

### Recommendation for Codex

**Validate:**

1. Autonomy of bidding flow (Steps 2-4 in architecture diagram)
2. Anti-spam effectiveness (threshold, crowded filter, workload penalty)
3. RAG integration (vector similarity queries before bid)
4. Confidential details access control
5. Test coverage (especially edge cases)

**Concerns:**

1. No encryption for confidential details (plaintext in DB)
2. No job execution autonomy (human still does work)
3. RAG integration not yet tested in integration tests
4. No monitoring/alerting for autonomy failures

**Overall Assessment:** 🟢 Bidding is genuinely autonomous, but job lifecycle is not.

---

**END OF VALIDATION GUIDE**
