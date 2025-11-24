# Implementation Checklist

## Overview

This document provides a step-by-step implementation guide for the photo classification feature. Follow each phase sequentially to ensure a smooth implementation.

---

## Phase 1: Database Setup

### 1.1 Create Migration File
- [x] Create `src/migrations/20241125010000_photo_classifications.sql` ✅
- [x] Schema includes 4 tables: `photo_classifications`, `tags`, `photo_tags`, `classification_logs` ✅
- [x] Indexes, FTS5 virtual table, and triggers included ✅
- [ ] Test migration locally with Wrangler

**Migration Files:**
```
src/migrations/
├── 20241125000000_init.sql                        (renamed from init.sql)
└── 20241125010000_photo_classifications.sql       (new)
```

**Commands:**
```bash
# Test migration locally
wrangler d1 execute unsplash_photos --local --file=./src/migrations/20241125010000_photo_classifications.sql

# Apply to production
wrangler d1 execute unsplash_photos --file=./src/migrations/20241125010000_photo_classifications.sql
```

**Note:** Migration files use timestamp format `YYYYMMDDHHmmss_name.sql` for versioning.
This allows copying migrations between repositories and applying in correct order.

### 1.2 Update TypeScript Types
- [ ] Add classification types to `src/helpers/types.ts`
- [ ] Define `PhotoClassification` interface (for main table)
- [ ] Define `Tag` interface (for tag dictionary)
- [ ] Define `ClassificationResult` interface (for API result)
- [ ] Define `ClassificationLog` interface (for logging)

**Example:**
```typescript
export interface PhotoClassification {
  photo_id: string;
  all_tags_searchable: string;
  classification_status: 'pending' | 'completed' | 'failed';
  confidence_score?: number;
  retry_count: number;
  last_attempt_ts?: number;
  completed_ts?: number;
  error_message?: string;
}

export interface Tag {
  tag_id: number;
  tag_name: string;
  tag_category: 'content' | 'people' | 'mood' | 'color' | 'quality';
  usage_count: number;
  created_ts: number;
}

export interface ClassificationResult {
  content_tags: string[];
  people_tags: string[];
  mood_tags: string[];
  color_tags: string[];
  quality_tags: string[];
  confidence_score: number;
}

export interface ClassificationLog {
  id: number;
  timestamp: number;
  photo_id: string;
  event_type: 'attempt' | 'success' | 'error' | 'model_fallback';
  model_used?: 'free' | 'paid';
  error_message?: string;
  processing_time_ms?: number;
  confidence_score?: number;
}
```

---

## Phase 2: Logging Setup

### 2.1 Create Logger Module
- [ ] Create `src/utils/logger.ts`
- [ ] Implement `WorkerLogger` class with 4 levels (DEBUG, INFO, WARN, ERROR)
- [ ] Add structured JSON logging
- [ ] Implement DB logging for critical events
- [ ] Add error handling (logging failures shouldn't break app)

**Key Methods:**
```typescript
class WorkerLogger {
  debug(message: string, meta?: LogMetadata): void
  info(message: string, meta?: LogMetadata): void
  async warn(message: string, meta?: LogMetadata): Promise<void>
  async error(message: string, error: Error, meta?: LogMetadata): Promise<void>
}
```

---

## Phase 3: OpenRouter API Integration

### 3.1 Create API Client Module
- [ ] Create `src/api/openrouter-client.ts`
- [ ] Implement `callOpenRouterAPI()` function with `model` parameter
- [ ] Implement `classifyPhotoWithFallback()` wrapper (free → paid)
- [ ] Implement `parseClassificationResponse()` function
- [ ] Add error handling and type definitions
- [ ] Add validation for classification response

**Key Functions:**
- `callOpenRouterAPI(photoUrl: string, apiKey: string, model: string): Promise<ClassificationResult>`
- `classifyPhotoWithFallback(photoUrl, apiKey, logger, photoId): Promise<{result, modelUsed}>`
- `parseClassificationResponse(response: OpenRouterResponse): ClassificationResult`

### 3.2 Create Prompt Template
- [ ] Create `src/prompts/classification-prompt.ts`
- [ ] Copy structured prompt from `api-integration.md`
- [ ] Export as constant `CLASSIFICATION_PROMPT`
- [ ] Consider making prompt customizable if needed

### 3.3 Add URL Generation Helper
- [ ] Create `src/helpers/photo-url.ts`
- [ ] Implement `generatePhotoUrl(rawPath: string): string`
- [ ] Add parameters for width and quality optimization
- [ ] Test with actual Unsplash photo paths

**Example:**
```typescript
export function generatePhotoUrl(
  rawPath: string,
  width: number = 600,
  quality: number = 80
): string {
  return `https://images.unsplash.com/${rawPath}?w=${width}&q=${quality}`;
}
```

---

## Phase 4: Classification Logic

### 4.1 Create Photo Classifier Module
- [ ] Create `src/classifiers/photo-classifier.ts`
- [ ] Implement main `classifyPhotos()` function
- [ ] Implement `classifySinglePhoto()` helper
- [ ] Add batch processing logic
- [ ] Implement retry mechanism

**Key Functions:**
```typescript
// Main entry point
async function classifyPhotos(
  env: Env,
  limit: number = 5
): Promise<ClassificationStats>

// Single photo classification
async function classifySinglePhoto(
  photo: Photo,
  apiKey: string
): Promise<ClassificationResult>

// Save to database
async function saveClassification(
  db: D1Database,
  photoId: string,
  classification: ClassificationResult
): Promise<void>

// Error handling
async function saveClassificationError(
  db: D1Database,
  photoId: string,
  error: string,
  retryCount: number
): Promise<void>
```

### 4.2 Implement Database Operations
- [ ] Create `src/db/classification-queries.ts`
- [ ] Implement `getUnclassifiedPhotos()`
- [ ] Implement `saveClassification()` - complex! (normalizes tags into 3 tables)
- [ ] Implement `getPhotoById()` for test endpoint
- [ ] Implement `getPhotoClassification()` - retrieves with tags by category
- [ ] Implement `updateClassificationError()`
- [ ] Implement `getClassificationStats()`

**Key Implementation Notes:**
`saveClassification()` must:
1. Build `all_tags_searchable` string (space-separated all tags)
2. Insert/update `photo_classifications` table
3. Delete old `photo_tags` relationships
4. For each tag: insert into `tags` (or increment usage_count), get tag_id, insert into `photo_tags`

**Query Functions:**
```typescript
async function getUnclassifiedPhotos(db: D1Database, limit: number): Promise<Photo[]>
async function saveClassification(db: D1Database, photoId: string, classification: ClassificationResult): Promise<void>
async function getPhotoById(db: D1Database, photoId: string): Promise<Photo | null>
async function getPhotoClassification(db: D1Database, photoId: string): Promise<PhotoClassification & ClassificationResult>
async function updateClassificationError(db: D1Database, photoId: string, errorMessage: string): Promise<void>
```

### 4.3 Add Validation Logic
- [ ] Create `src/validators/classification-validator.ts`
- [ ] Implement tag validation rules
- [ ] Check people_tags requirements
- [ ] Validate minimum tag counts
- [ ] Check confidence threshold

---

## Phase 5: Cron Integration

### 5.1 Update Main Worker File
- [ ] Modify `src/index.ts`
- [ ] Import classifier module
- [ ] Add classification logic to `scheduled()` handler
- [ ] Keep existing token cleanup logic
- [ ] Add error handling and logging

**Example Structure:**
```typescript
async function scheduled(
  controller: ScheduledController,
  env: Env,
  ctx: ExecutionContext
) {
  try {
    // Existing: Clean up expired tokens
    await cleanupExpiredTokens(env);
    
    // New: Classify photos
    await classifyPhotos(env, 5);
    
    console.log('Cron processed successfully');
  } catch (error) {
    console.error('Cron error:', error);
    throw error;
  }
}
```

### 5.2 Add Manual Trigger Endpoints

**Batch Classification Endpoint:**
- [ ] Update `fetch()` handler in `src/index.ts`
- [ ] Add route for `/classify-photos`
- [ ] Implement manual trigger logic
- [ ] Return classification stats in response

**Test Classification Endpoint:**
- [ ] Create `src/handlers/test-classify.ts`
- [ ] Implement `handleTestClassify(request, env)` function
- [ ] Create `generateSuccessHTML()` function for visual results
- [ ] Create `generateErrorHTML()` function for errors
- [ ] Add route for `/test-classify` in main worker
- [ ] Test endpoint performs FULL classification + save to DB

See [test-endpoint.md](./test-endpoint.md) for detailed implementation.

**Example Routes:**
```typescript
async function fetch(request: Request, env: Env, ctx: ExecutionContext) {
  const url = new URL(request.url);
  
  // Batch classification
  if (url.pathname === '/classify-photos') {
    const stats = await classifyPhotos(env, 10);
    return Response.json({ success: true, stats });
  }
  
  // Test single photo with HTML result
  if (url.pathname === '/test-classify') {
    return await handleTestClassify(request, env);
  }
  
  return new Response('Beautiful Photos Worker Cron');
}
```

### 5.3 Update Wrangler Configuration
- [ ] Update `wrangler.jsonc`
- [ ] Add new cron schedule if different from existing
- [ ] Ensure environment variables are configured
- [ ] Test configuration syntax

**Example:**
```jsonc
{
  "triggers": {
    "crons": [
      "*/5 * * * *",  // Existing: token cleanup every 5 minutes
      "* * * * *"     // New: photo classification every minute
    ]
  }
}
```

---

## Phase 6: Environment Configuration

### 6.1 Update Environment Variables
- [ ] Add `OPENROUTER_API_KEY` to `.dev.vars` (already done)
- [ ] Verify API key is valid
- [ ] Test API connection

### 6.2 Configure Production Secrets
- [ ] Set production secret for `OPENROUTER_API_KEY`
```bash
wrangler secret put OPENROUTER_API_KEY
```

### 6.3 Update TypeScript Env Interface
- [ ] Update `Env` interface in `src/index.ts` or types file
```typescript
interface Env {
  DB: D1Database;
  OPENROUTER_API_KEY: string;
  ENVIRONMENT?: 'development' | 'production'; // Optional for logger
}
```

---

## Phase 7: Testing

### 7.1 Unit Tests
- [ ] Create test file `test/logger.spec.ts` for logger
- [ ] Create test file `test/classification.spec.ts`
- [ ] Test URL generation function
- [ ] Test response parsing logic
- [ ] Test validation functions
- [ ] Mock OpenRouter API responses

### 7.2 Integration Tests
- [ ] Test database operations locally
- [ ] Test full classification flow with mock data
- [ ] Test error handling paths
- [ ] Test retry logic

### 7.3 Manual Testing

**Using Test Endpoint:**
- [ ] Run local dev server: `npm run dev`
- [ ] Open browser: `http://localhost:8787/test-classify?photo_id=YOUR_PHOTO_ID`
- [ ] Verify HTML displays correctly with photo and classification
- [ ] Check if model used is shown (free/paid)
- [ ] Verify data saved to database
- [ ] Test with invalid photo_id (should show error page)

**Using Batch Endpoint:**
- [ ] Trigger manual classification: `curl http://localhost:8787/classify-photos`
- [ ] Check logs for errors
- [ ] Verify database updates

**Test Checklist:**
- [ ] Photos without people
- [ ] Photos with close people (portrait, <2m, >30% frame)
- [ ] Photos with distant people
- [ ] Different content types (nature, urban, architecture, etc.)
- [ ] Edge cases (blurred, dark photos, etc.)
- [ ] Free model works (most cases)
- [ ] Fallback to paid model works (simulate by using invalid free model)
- [ ] Logging works (check console and database)

---

## Phase 8: Deployment

### 8.1 Pre-Deployment Checks
- [ ] All tests passing
- [ ] No TypeScript errors
- [ ] Code reviewed and cleaned up
- [ ] Logging is appropriate (not too verbose)
- [ ] Error handling is comprehensive

### 8.2 Deploy Database Migration
- [ ] Backup production database (if possible)
- [ ] Run migration in production
```bash
wrangler d1 execute unsplash_photos --file=./src/migrations/20241125010000_photo_classifications.sql
```
- [ ] Verify tables created successfully
```sql
-- Verify tables exist
SELECT name FROM sqlite_master WHERE type='table' 
AND name IN ('photo_classifications', 'tags', 'photo_tags', 'classification_logs');

-- Verify FTS5 table
SELECT name FROM sqlite_master WHERE type='table' AND name='photo_classifications_fts';
```

### 8.3 Deploy Worker
- [ ] Deploy to production
```bash
npm run deploy
```
- [ ] Verify deployment successful
- [ ] Check worker logs in Cloudflare dashboard

### 8.4 Set Production Secrets
- [ ] Set `OPENROUTER_API_KEY` secret
```bash
wrangler secret put OPENROUTER_API_KEY
```

---

## Phase 9: Monitoring & Validation

### 9.1 Initial Monitoring
- [ ] Monitor Cloudflare Worker logs (real-time via Dashboard or `wrangler tail`)
- [ ] Check cron execution frequency
- [ ] Verify classifications are being saved to all 3 tables
- [ ] Monitor API usage and costs (check for paid model usage)
- [ ] Check for errors in logs (both console and database)
- [ ] Monitor model fallback frequency (should be <10%)

### 9.2 Data Validation
- [ ] Query database for classification stats
```sql
-- Classification status
SELECT classification_status, COUNT(*) as count
FROM photo_classifications
GROUP BY classification_status;

-- Tag statistics
SELECT tag_category, COUNT(*) as unique_tags, SUM(usage_count) as total_usage
FROM tags
GROUP BY tag_category;

-- Model usage
SELECT model_used, COUNT(*) as count
FROM classification_logs
WHERE model_used IS NOT NULL
GROUP BY model_used;
```
- [ ] Sample check classification quality using test endpoint
- [ ] Verify tag distributions make sense (top 20 tags query)
- [ ] Check confidence scores
- [ ] Verify `all_tags_searchable` field is populated correctly

### 9.3 Performance Monitoring
- [ ] Monitor worker CPU time usage
- [ ] Check average classification time
- [ ] Monitor API response times
- [ ] Track token usage and costs

**Key Metrics to Track:**
- Classifications per minute
- Success/failure rate
- Average confidence score
- CPU time per execution
- API costs
- Queue depth (unclassified photos)

---

## Phase 10: Optimization (Post-Launch)

### 10.1 Batch Processing Optimization
- [ ] Test if OpenRouter supports multi-image requests
- [ ] If yes, implement batch API calls
- [ ] Adjust batch size based on performance
- [ ] Monitor cost savings

### 10.2 Performance Tuning
- [ ] Analyze slow queries (especially normalized joins)
- [ ] Analyze slow queries
- [ ] Optimize database indexes if needed
- [ ] Adjust cron frequency based on needs
- [ ] Fine-tune confidence thresholds

### 10.3 Cost Optimization
- [ ] Monitor API costs per photo
- [ ] Track free vs paid model usage ratio
- [ ] Alert if >20% using paid model (indicates quota issues)
- [ ] Optimize image sizes if costs are high
- [ ] Consider caching frequently classified patterns
- [ ] Adjust processing rate if needed

---

## Phase 11: Documentation Updates

### 11.1 Update Memory Bank
- [ ] Update `memory-bank/projectbrief.md` with new feature
- [ ] Update `memory-bank/systemPatterns.md` with normalized DB architecture
- [ ] Update `memory-bank/techContext.md` with new dependencies
- [ ] Update `memory-bank/progress.md` with completion status
- [ ] Update `memory-bank/activeContext.md` with learnings and patterns

### 11.2 Update README
- [ ] Document new classification feature
- [ ] Add setup instructions
- [ ] Document both endpoints (`/classify-photos` and `/test-classify`)
- [ ] Add troubleshooting section
- [ ] Document model fallback strategy

---

## Rollback Plan

If issues arise in production:

### Quick Rollback Steps
1. **Disable Cron**: Comment out classification cron in `wrangler.jsonc` and redeploy
2. **Revert Deployment**: Deploy previous version
```bash
git revert HEAD
npm run deploy
```
3. **Database Cleanup**: If needed, drop classification tables
```sql
DROP TABLE IF EXISTS photo_classifications_fts;
DROP TABLE IF EXISTS photo_classifications;
```

### Partial Rollback
- Keep tables but disable cron processing
- Fix issues and redeploy
- Resume processing once stable

---

## Success Criteria

The implementation is considered successful when:

- [ ] All phases completed without critical issues
- [ ] Classification cron runs every minute successfully
- [ ] Photos are being classified with >80% success rate
- [ ] Average confidence score is >0.7
- [ ] No errors in last 24 hours of logs
- [ ] CPU time stays under 10ms per execution
- [ ] API costs are within budget
- [ ] Manual trigger endpoint works reliably
- [ ] Extension can query classifications successfully
- [ ] Team is satisfied with tag quality

---

## Timeline Estimate

- **Phase 1**: 1-2 hours (Database setup - more complex with normalized schema)
- **Phase 2**: 1 hour (Logging setup)
- **Phase 3**: 2-3 hours (API integration with fallback)
- **Phase 4**: 3-4 hours (Classification logic with complex DB operations)
- **Phase 5**: 1-2 hours (Cron integration + test endpoint)
- **Phase 6**: 30 minutes (Environment config)
- **Phase 7**: 2-3 hours (Testing - more scenarios with fallback and logging)
- **Phase 8**: 1 hour (Deployment)
- **Phase 9**: 1-2 hours (Monitoring)
- **Phase 10**: Ongoing (Optimization)
- **Phase 11**: 1 hour (Documentation)

**Total Estimated Time**: 14-20 hours across 2-3 sessions

---

## Notes

- Take breaks between phases
- Commit code frequently
- Test thoroughly before deploying
- Monitor closely after deployment
- Document any issues or learnings
- Keep this checklist updated with progress
