# Architecture Documentation

## Table of Contents

- [System Overview](#system-overview)
- [Architecture Diagram](#architecture-diagram)
- [Cloud Services](#cloud-services)
- [Data Models](#data-models)
- [Component Design](#component-design)
- [Data Flow](#data-flow)
- [Stateless Design](#stateless-design)
- [Security & IAM](#security--iam)
- [Scalability & Performance](#scalability--performance)

---

## System Overview

CAB432 Video Transcoding Platform is a **cloud-native**, **stateless**, **event-driven** video processing application. The system follows a **microservice-inspired** pattern with clear separation of concerns:

- **API Server** (Express): Handles HTTP requests, authentication, metadata CRUD
- **Background Worker**: Polls job queue, transcodes videos, generates thumbnails, updates metadata
- **Frontend SPA**: Static HTML/JS served from Express, talks to REST API

### Core Principles

1. **Statelessness**: All persistent state lives in AWS services (S3, DynamoDB, Secrets Manager, Parameter Store). The app can be restarted or scaled horizontally without losing data.
2. **Eventual Consistency**: Video transcoding is asynchronous; users poll for status updates.
3. **Cloud-Native**: Leverages managed AWS services for auth, storage, database, configuration, and caching.
4. **Fail-Safe**: Worker handles aborts, timeouts, and stale locks; cache gracefully degrades if unavailable.

---

## Architecture Diagram

```
┌─────────────────────────────────────────────────────────────────────────┐
│                              Client (Browser)                            │
│  - Login/Signup UI                                                       │
│  - Video upload, list, stream                                            │
└────────────────────┬────────────────────────────────────────────────────┘
                     │ HTTPS (via Route53 CNAME → EC2/ALB)
                     ▼
┌─────────────────────────────────────────────────────────────────────────┐
│                         Express API Server (Node.js)                     │
│  - Routes: /api/v1/auth, /api/v1/videos, /api/v1/media, /api/v1/me     │
│  - Middleware: JWT verification (Cognito), CORS, request validation      │
│  - Static: Serves public/ (SPA)                                          │
└───┬─────────┬─────────┬─────────┬──────────┬──────────┬─────────────────┘
    │         │         │         │          │          │
    ▼         ▼         ▼         ▼          ▼          ▼
┌─────────┐ ┌───────┐ ┌───────┐ ┌──────┐ ┌──────┐ ┌────────────┐
│ Cognito │ │  S3   │ │ DDB   │ │ SSM  │ │Secret│ │ElastiCache │
│UserPool │ │Bucket │ │Table  │ │Param │ │Mgr   │ │(Memcached) │
└─────────┘ └───────┘ └───────┘ └──────┘ └──────┘ └────────────┘
    │         │         │         │          │          │
    │         │         │         │          │          │
    │         │         │         │          │          │
    │         └─────────┴─────────┴──────────┴──────────┘
    │                   │                               │
    ▼                   ▼                               ▼
┌─────────────────────────────────────────────────────────────────────────┐
│                      Background Worker (same container)                  │
│  - Polls DynamoDB for queued videos                                      │
│  - Downloads original from S3                                            │
│  - Transcodes via FFmpeg (1080p, 720p, 480p)                            │
│  - Generates thumbnail, auto-tags via Hugging Face API                  │
│  - Uploads renditions/thumbnail to S3                                    │
│  - Updates DynamoDB (status, renditions, tags, duration)                │
└─────────────────────────────────────────────────────────────────────────┘
```

### Component Responsibilities

| Component | Responsibility |
|-----------|---------------|
| **Client (Browser)** | User interface, direct S3 upload via presigned URLs |
| **Express API** | Authentication, video metadata CRUD, presigned URL generation |
| **Cognito** | User registration, confirmation, login, JWT issuance |
| **S3** | Object storage (originals, renditions, thumbnails) |
| **DynamoDB** | Video metadata, job queue, worker locks |
| **Secrets Manager** | Sensitive config (Cognito secret, HF token) |
| **Parameter Store** | Non-sensitive config (region, model name, TTLs) |
| **ElastiCache** | In-memory cache for video list queries |
| **Background Worker** | Video transcoding, thumbnail generation, auto-tagging |
| **Hugging Face API** | Image classification for thumbnail auto-tagging |

---

## Cloud Services

### AWS Cognito (Authentication)

- **User Pool**: Manages users, passwords, email confirmation
- **JWT Tokens**: IdToken with `cognito:groups` claim used for authorization
- **Groups**: `Admin` group grants delete permissions
- **Integration**: `aws-jwt-verify` library validates JWTs on every protected route

**Flow**:
1. Client: `POST /api/v1/auth/register` → Cognito SignUp
2. Cognito sends confirmation email
3. Client: `POST /api/v1/auth/confirm` → Cognito ConfirmSignUp
4. Client: `POST /api/v1/auth/login` → Cognito InitiateAuth → returns JWT IdToken
5. Client sends `Authorization: Bearer <token>` on all protected routes
6. Server verifies JWT signature and expiry via `aws-jwt-verify`

### Amazon S3 (Object Storage)

- **Private Bucket**: No public access; all objects accessed via presigned URLs
- **Key Structure**:
  - Original: `user/{userId}/videos/{videoId}/original.mp4`
  - Renditions: `user/{userId}/videos/{videoId}/renditions/{resolution}.mp4`
  - Thumbnail: `user/{userId}/videos/{videoId}/thumbnail.jpg`
- **Presigned URLs**: Generated via `@aws-sdk/s3-request-presigner`
  - Upload: `PUT` URL for client → S3 (60 min expiry)
  - Download: `GET` URL for streaming/download (60 min expiry)

**Benefits**:
- Offloads traffic from API server
- Secure: URLs expire, no credentials in client
- Scalable: S3 handles unlimited objects

### Amazon DynamoDB (Metadata & Job Queue)

- **Table**: Single-table design with partition key `qut-username` and sort key `SK`
- **Items**:
  - **Video**: `SK = USER#<userId>#VIDEO#<videoId>`
    - Attributes: `title`, `status`, `originalKey`, `thumbnailKey`, `renditions`, `tags`, `duration`, `errorMessage`, `transcodeLockedBy`, `transcodeLockedAt`, `createdAt`, `updatedAt`
  - **User Profile** (future): `SK = USERPROFILE#<username>`

**Video Status Lifecycle**:
```
queued → processing → completed
              ↓
           failed (on error or cancel)
```

**Worker Locking**:
- Worker claims a `queued` video by setting `transcodeLockedBy` and `transcodeLockedAt` with a conditional write (ensures only one worker processes a job)
- Stale locks (older than `TRANSCODE_LOCK_TTL_MS`) are reclaimed and re-queued
- On completion/failure, lock is removed

### AWS Secrets Manager

- **Secret Name**: `group57/A2/secret`
- **Format**: JSON
  ```json
  {
    "COGNITO_CLIENT_SECRET": "...",
    "HF_API_TOKEN": "hf_..."
  }
  ```
- **Loading**: `src/config/secretManager.js` fetches secret on startup, merges into `process.env`

### AWS Systems Manager Parameter Store

- **Prefix**: `/cab432/g57/app/`
- **Parameters**:
  - `AWS_REGION`, `PORT`, `JWT_EXPIRES`
  - `HF_IMAGE_MODEL`, `TAGS_TOP_K`, `TAGS_MIN_SCORE`
  - `QUT_USERNAME`, `TRANSCODE_LOCK_TTL_MS`
- **Loading**: `src/config/parameterStore.js` fetches missing env vars on demand
- **Benefits**: Centralized config, no hardcoding, easy updates without redeployment

### AWS ElastiCache (Memcached)

- **Cluster**: Memcached 1.6 with 128 MB memory, 2 MB max item size
- **Endpoint**: `g57-memcache.km2jzi.cfg.apse2.cache.amazonaws.com:11211`
- **Client**: `memcached` npm package with timeouts, retries, reconnect logic
- **Cache Strategy**: Namespace-based invalidation
  - Key format: `listVideos:v1:<userId>:ns<namespace>:<query-params>`
  - Namespace counter incremented on mutations (create, complete, delete)
  - Cache miss → query DynamoDB → store in cache (90s TTL)
  - Cache hit → return cached response
- **Graceful Degradation**: If Memcached is unavailable, requests fall back to DynamoDB

**Benefits**:
- Reduces DynamoDB read capacity for hot queries
- Sub-millisecond response times for cached lists
- Stateless: cache can be flushed without data loss

### Hugging Face Inference API

- **Model**: `microsoft/resnet-50` (image classification)
- **Usage**: Worker uploads thumbnail → HF API → returns top-K labels with scores
- **Filtering**: Only labels with score ≥ `TAGS_MIN_SCORE` are stored
- **Retries**: Worker tolerates transient HF errors (logs warning, continues)

---

## Data Models

### DynamoDB Video Item

```javascript
{
  "qut-username": "n1234567@qut.edu.au",  // Partition key (shared by all videos)
  "SK": "USER#<userId>#VIDEO#<videoId>",  // Sort key (unique per video)
  "type": "Video",
  "userId": "<cognito-sub>",
  "videoId": "<uuid>",
  "title": "My Video",
  "status": "completed",  // queued | processing | completed | failed
  "originalKey": "user/<userId>/videos/<videoId>/original.mp4",
  "baseKey": "user/<userId>/videos/<videoId>",
  "thumbnailKey": "user/<userId>/videos/<videoId>/thumbnail.jpg",
  "renditions": [
    { "resolution": "1080", "s3Key": "...", "sizeBytes": 12345678 },
    { "resolution": "720", "s3Key": "...", "sizeBytes": 8901234 },
    { "resolution": "480", "s3Key": "...", "sizeBytes": 5678901 }
  ],
  "tags": [
    { "tag": "nature", "score": 0.87 },
    { "tag": "landscape", "score": 0.72 }
  ],
  "duration": 120,  // seconds
  "errorMessage": null,
  "sourceType": "upload",  // upload | youtube (future)
  "sourceUrl": null,
  "transcodeLockedBy": "hostname-12345-abc123",  // Worker ID (null if not locked)
  "transcodeLockedAt": "2025-10-19T12:34:56.789Z",  // ISO timestamp
  "createdAt": "2025-10-19T10:00:00.000Z",
  "updatedAt": "2025-10-19T12:35:00.000Z"
}
```

### API Video Response

```javascript
{
  "id": "<videoId>",
  "userId": "<cognito-sub>",
  "title": "My Video",
  "status": "completed",
  "duration": 120,
  "originalKey": "user/...",
  "thumbnailKey": "user/.../thumbnail.jpg",
  "renditions": [
    { "resolution": "1080", "s3Key": "...", "sizeBytes": 12345678 },
    { "resolution": "720", "s3Key": "...", "sizeBytes": 8901234 },
    { "resolution": "480", "s3Key": "...", "sizeBytes": 5678901 }
  ],
  "tags": ["nature", "landscape"],  // Flattened from tag objects
  "errorMessage": null,
  "sourceType": "upload",
  "sourceUrl": null,
  "createdAt": "2025-10-19T10:00:00.000Z",
  "updatedAt": "2025-10-19T12:35:00.000Z"
}
```

---

## Component Design

### API Server (`src/index.js`)

**Responsibilities**:
- Bootstrap Express app
- Load secrets from Secrets Manager (`loadSecrets()`)
- Load parameters from Parameter Store (`ensureParametersLoaded()`)
- Mount routes: `/api/v1/auth`, `/api/v1/me`, `/api/v1/videos`, `/api/v1/media`
- Serve static frontend from `public/`
- Start background worker (`startTranscodeWorker()`)
- Graceful shutdown on SIGTERM/SIGINT

**Middleware Stack**:
1. CORS (configurable origin)
2. Morgan (HTTP logging)
3. Body parser (JSON, 10 MB limit)
4. Route handlers
5. Error handling (implicit 500 on unhandled errors)

### Routes

#### `src/routes/auth.js`
- `POST /api/v1/auth/register`: Cognito SignUp
- `POST /api/v1/auth/confirm`: Cognito ConfirmSignUp
- `POST /api/v1/auth/login`: Cognito InitiateAuth → returns JWT

#### `src/routes/me.js`
- `GET /api/v1/me`: Returns decoded JWT user info (protected)

#### `src/routes/videos.js`
- `POST /api/v1/videos/upload-url`: Generate presigned S3 PUT URL
- `POST /api/v1/videos/:id/complete`: Mark presigned upload complete, queue transcode
- `POST /api/v1/videos`: Multipart upload (fallback for small files)
- `GET /api/v1/videos`: List videos with pagination, filtering, caching
- `GET /api/v1/videos/:id`: Get single video with ETag support
- `POST /api/v1/videos/:id/cancel`: Cancel in-progress transcode
- `DELETE /api/v1/videos/:id`: Admin-only delete (S3 + DynamoDB)

**Caching Strategy**:
- `GET /api/v1/videos` checks cache first (key includes userId, query params, namespace)
- Cache miss → query DynamoDB → store in cache (90s TTL)
- Mutations (create, complete, delete) bump namespace counter → invalidates all cached lists for that user

#### `src/routes/media.js`
- `GET /api/v1/videos/:id/stream?res=<resolution>`: Presigned GET URL for video
- `GET /api/v1/videos/:id/download?res=<resolution>`: Presigned GET URL with `Content-Disposition: attachment`
- `GET /api/v1/videos/:id/thumb`: Presigned GET URL for thumbnail (or fallback SVG)

### Middleware (`src/middleware/auth.js`)

#### `authRequired`
- Extracts JWT from `Authorization: Bearer <token>` header or `?token=<token>` query param
- Verifies JWT signature and expiry via `aws-jwt-verify`
- Attaches decoded payload to `req.user` (includes `sub`, `cognito:groups`, etc.)
- Returns 401 if token is missing/invalid

#### `requireGroup(groupName)`
- Checks if `req.user.groups` includes `groupName`
- Returns 403 if user is not in the group
- Used for admin-only routes (e.g., `DELETE /api/v1/videos/:id`)

### Background Worker (`src/worker/transcodeWorker.js`)

**Responsibilities**:
- Poll DynamoDB for `queued` videos every 5 seconds (configurable via `TRANSCODE_POLL_MS`)
- Claim job with worker lock (conditional write to prevent race conditions)
- Download original video from S3 to temp directory
- Transcode to 1080p, 720p, 480p using FFmpeg (`src/lib/ffmpeg.js`)
- Extract thumbnail at 3s mark
- Upload renditions and thumbnail to S3
- Classify thumbnail via Hugging Face API (`src/lib/tagger.js`)
- Update DynamoDB with `completed` status, renditions, thumbnail key, duration, tags
- On error: mark `failed` with error message
- On cancel: detect `AbortController` signal, mark `failed` with "Canceled by user"
- Clean up temp directory

**Concurrency Model**:
- Single worker processes one job at a time (sequential)
- Multiple instances can run in parallel; DynamoDB locks prevent collisions
- Stale locks (older than `TRANSCODE_LOCK_TTL_MS`) are reclaimed and re-queued

**FFmpeg Integration** (`src/lib/ffmpeg.js`):
- `ffprobeDurationSeconds(inputPath)`: Extracts video duration
- `transcodeProfiles(original, profiles, opts)`: Transcodes to multiple resolutions
  - Uses `libx264` codec, `aac` audio, CRF quality (22-24), adaptive bitrate
  - Supports abort signals for graceful cancellation
- `extractThumbnail(original, outThumb, atSec, opts)`: Extracts JPEG frame at specified second

**Auto-Tagging** (`src/lib/tagger.js`):
- Uploads thumbnail bytes to Hugging Face Inference API
- Model: `microsoft/resnet-50` (configurable via Parameter Store)
- Returns top-K labels with scores (configurable `TAGS_TOP_K`, `TAGS_MIN_SCORE`)
- Filters out low-confidence labels
- Tolerates API errors (logs warning, continues without tags)

### Cache Layer (`src/lib/cache.js`)

**Implementation**:
- Memcached client with connection pooling, retries, timeouts
- **Namespace-based invalidation**: Each user has a namespace counter (stored in Memcached)
  - Key format: `listVideos:v1:<userId>:ns<namespace>:<query-params>`
  - On mutation: increment namespace counter → all cached keys become stale
  - Next query uses new namespace → cache miss → fresh data from DynamoDB
- **Graceful degradation**: All cache operations wrapped in try-catch
  - If Memcached is unreachable, functions return `null` (cache miss) → query DynamoDB

**Cache Key Structure**:
```
listVideos:v1:<userId>:ns<namespace>:page=1&pageSize=10&status=completed
```

**Benefits**:
- Avoids cache stampede (namespace bump is atomic)
- Simplifies invalidation (no need to scan/delete keys)
- Supports query param variations (each query has unique key)

### Data Access Layer (`src/lib/paths.js`)

**`videoRepo` Object**:
- Abstraction over DynamoDB operations
- Methods:
  - `create({ userId, videoId, title, originalKey, duration })`: Insert video with `queued` status
  - `listAll()`: Query all videos (for admins)
  - `listByUser(userId)`: Query videos for specific user
  - `get(userId, videoId)`: Fetch single video
  - `markProcessing(userId, videoId, workerId)`: Claim job (conditional write)
  - `markCompleted(userId, videoId, { duration, thumbnailKey, renditions, tags })`: Update on success
  - `markFailed(userId, videoId, errorMessage)`: Update on failure
  - `markCanceled(userId, videoId)`: Mark as failed with "Canceled" message
  - `remove(userId, videoId)`: Delete item (admin only)
  - `claimNextQueuedVideo(workerId, limit)`: Atomic claim of next queued job
  - `findStaleProcessing(cutoffIso, limit)`: Find jobs with old locks
  - `requeueVideo(userId, videoId)`: Re-queue stale job

**S3/DynamoDB Client Factories**:
- `getS3Client()`, `getDynamoClient()`, `getDdbDocClient()`: Lazy-initialized AWS SDK clients
- `getRegion()`, `getS3Bucket()`, `getDynamoTable()`, `getQutUsername()`: Env var getters with validation

---

## Data Flow

### Upload Flow (Presigned URL Method)

```
1. Client → POST /api/v1/videos/upload-url
   ↓
2. API generates presigned S3 PUT URL (60 min expiry)
   ↓
3. API returns { videoId, uploadUrl, expiresIn, method: "PUT" }
   ↓
4. Client → PUT <uploadUrl> (directly to S3, no API involvement)
   ↓
5. Client → POST /api/v1/videos/:id/complete
   ↓
6. API verifies object exists in S3 (HeadObjectCommand)
   ↓
7. API creates DynamoDB item with status="queued"
   ↓
8. API bumps cache namespace (invalidates user's video list cache)
   ↓
9. API notifies worker (triggers immediate poll)
   ↓
10. Worker claims job → transcodes → uploads renditions/thumbnail → updates DynamoDB
```

### Transcode Flow

```
1. Worker polls DynamoDB for queued videos
   ↓
2. Worker claims job (conditional write: status=queued, no lock)
   ↓
3. Worker downloads original from S3 to /tmp/<uuid>/original.mp4
   ↓
4. Worker runs FFmpeg to transcode to 1080p, 720p, 480p
   ↓
5. Worker uploads renditions to S3
   ↓
6. Worker extracts thumbnail at 3s mark → uploads to S3
   ↓
7. Worker classifies thumbnail via Hugging Face API
   ↓
8. Worker updates DynamoDB:
   - status = "completed"
   - duration, thumbnailKey, renditions, tags
   - clears lock
   ↓
9. Worker cleans up /tmp/<uuid>
   ↓
10. Client polls GET /api/v1/videos/:id → sees status="completed"
```

### Stream/Download Flow

```
1. Client → GET /api/v1/videos/:id/stream?res=720
   ↓
2. API verifies user owns video (or is admin)
   ↓
3. API looks up video in DynamoDB
   ↓
4. API finds rendition S3 key for resolution=720
   ↓
5. API generates presigned S3 GET URL (60 min expiry)
   ↓
6. API returns { url, expiresIn }
   ↓
7. Client → GET <url> (directly from S3, no API involvement)
```

### Cache Flow (Video List)

```
1. Client → GET /api/v1/videos?page=1&status=completed
   ↓
2. API builds cache key: listVideos:v1:<userId>:ns<namespace>:page=1&status=completed
   ↓
3. API checks Memcached for key
   ↓
   ├─ HIT → return cached response (logs CACHE_HIT)
   │
   └─ MISS → query DynamoDB (logs CACHE_MISS)
      ↓
      Filter/sort/paginate results
      ↓
      Store in Memcached (90s TTL)
      ↓
      Return response
```

**Invalidation**:
```
1. Client → POST /api/v1/videos (upload)
   ↓
2. API creates video in DynamoDB
   ↓
3. API increments namespace counter for userId
   ↓
4. Next list query uses new namespace → cache miss → fresh data
```

---

## Stateless Design

### Principles

1. **No Local State**: App does not store data on disk (except temp files during transcode)
2. **Idempotent Operations**: Restart-safe; worker re-claims stale jobs
3. **Distributed Lock**: DynamoDB conditional writes prevent race conditions
4. **Config Externalized**: Secrets Manager + Parameter Store hold all config
5. **Session-less Auth**: JWT verification is stateless (no server-side sessions)

### Restart Safety

**Scenario**: App crashes mid-transcode

**Recovery**:
1. Worker `transcodeLockedAt` timestamp becomes stale (> `TRANSCODE_LOCK_TTL_MS`)
2. New worker instance calls `findStaleProcessing()` → finds stale job
3. Worker resets job to `queued` status, clears lock
4. Worker processes job from scratch (idempotent: overwrites S3 objects if they exist)

**Scenario**: Multiple workers deployed

**Coordination**:
- Worker A claims job with conditional write (only succeeds if status=queued, no lock)
- Worker B tries to claim same job → conditional write fails → moves to next job
- No collisions; each job processed exactly once

### Horizontal Scaling

**Current State**: Single container runs API + worker

**Future (Assessment 3)**:
- **API Tier**: Multiple EC2 instances behind Application Load Balancer (stateless, read cache)
- **Worker Tier**: Multiple EC2 instances (or ECS tasks) running worker only (no API)
- **Auto Scaling**: Scale based on DynamoDB `queued` count or CPU/memory metrics
- **Cache Coherence**: Namespace invalidation ensures all API instances see fresh data

**No Changes Required**: App is already stateless; just deploy more instances.

---

## Security & IAM

### IAM Roles

**EC2 Instance Role** (attached to instance):
- `AmazonEC2ContainerRegistryReadOnly` (pull Docker images from ECR)
- `AmazonS3FullAccess` (or scoped: `s3:GetObject`, `s3:PutObject`, `s3:DeleteObject` on `<bucket>/*`)
- `AmazonDynamoDBFullAccess` (or scoped: `dynamodb:PutItem`, `dynamodb:GetItem`, `dynamodb:Query`, `dynamodb:UpdateItem`, `dynamodb:DeleteItem` on table ARN)
- `SecretsManagerReadWrite` (or read-only: `secretsmanager:GetSecretValue` on secret ARN)
- `AmazonSSMReadOnlyAccess` (or scoped: `ssm:GetParameters` on `/cab432/g57/app/*`)

**Bucket Policy** (S3):
```json
{
  "Version": "2012-10-17",
  "Statement": [
    {
      "Effect": "Deny",
      "Principal": "*",
      "Action": "s3:*",
      "Resource": "arn:aws:s3:::<bucket>/*",
      "Condition": {
        "Bool": { "aws:SecureTransport": "false" }
      }
    }
  ]
}
```
- Enforces HTTPS for all S3 requests
- No public access; all access via presigned URLs

### Authentication Flow

1. User registers → Cognito creates user (unconfirmed)
2. Cognito sends confirmation email
3. User confirms → Cognito marks user as confirmed
4. User logs in → Cognito returns JWT IdToken
5. Client stores token (localStorage or sessionStorage)
6. Client sends `Authorization: Bearer <token>` on every API request
7. API verifies token signature and expiry via `aws-jwt-verify` (no database lookup)

### Authorization

- **Group-based**: Cognito groups (`Admin`) included in JWT claims
- **Middleware**: `requireGroup("Admin")` checks `req.user.groups`
- **Ownership**: Most routes filter by `req.user.sub` (only show user's own videos)
- **Admin Override**: Admin routes (`listAll()`) bypass ownership filter

### Secrets

**Sensitive**:
- `COGNITO_CLIENT_SECRET`: Stored in Secrets Manager
- `HF_API_TOKEN`: Stored in Secrets Manager

**Non-Sensitive**:
- `AWS_REGION`, `PORT`, `HF_IMAGE_MODEL`: Stored in Parameter Store

**Never Hardcoded**: All secrets loaded at runtime from AWS services.

---

## Scalability & Performance

### Current Bottlenecks

1. **Worker Concurrency**: Single worker processes one job at a time
   - **Solution**: Deploy multiple worker instances (already supported via DynamoDB locks)

2. **DynamoDB Read Capacity**: High traffic on `GET /api/v1/videos` can throttle
   - **Solution**: Memcached caching reduces reads by ~80% for hot queries

3. **S3 Upload Throughput**: Large files take time to upload
   - **Solution**: Presigned URLs offload upload traffic from API server

### Optimization Strategies

#### Caching
- **Layer**: Memcached (ElastiCache)
- **Hit Rate**: ~90% for video list queries (after warm-up)
- **TTL**: 90 seconds (configurable via `VIDEOS_CACHE_TTL_SECONDS`)
- **Invalidation**: Namespace bump on mutations (atomic, no scan-and-delete)

#### Presigned URLs
- **Upload**: Client → S3 directly (no API bandwidth consumed)
- **Download**: Client → S3 directly (no API bandwidth consumed)
- **Security**: URLs expire after 60 minutes, cannot be shared long-term

#### FFmpeg Optimization
- **Profiles**: CRF 22-24 (good quality, moderate file size)
- **Preset**: `slow` (better compression at cost of longer transcode time)
- **Parallel**: Future: transcode multiple resolutions in parallel (requires ffmpeg multi-output or concurrent spawns)

#### Database Design
- **Single-Table**: Reduces round-trips (all video metadata in one item)
- **Sparse Indexes** (future): GSI on `status` for efficient queue polling
- **Batch Operations**: `BatchGetItem` for multi-video fetches (not yet implemented)

### Monitoring & Observability

**Logs**:
- API requests: Morgan middleware (`dev` format)
- Worker progress: Console logs with `[worker]` prefix
- Cache hits/misses: `CACHE_HIT`, `CACHE_MISS` logs
- Errors: `console.error` with stack traces

**Metrics** (future):
- CloudWatch Logs for centralized log aggregation
- CloudWatch Metrics: API latency, DynamoDB read/write capacity, S3 request count
- X-Ray tracing for distributed request flow

**Alerts** (future):
- DynamoDB throttling
- Worker queue depth > threshold
- S3 bucket size or request rate anomalies

---

## Future Enhancements (Assessment 3)

1. **TLS/HTTPS**: Add ALB with ACM certificate, update Route53 to point to ALB
2. **Auto Scaling**: Scale API and worker tiers independently based on load
3. **CDN**: CloudFront for thumbnail/rendition caching at edge
4. **Async Notifications**: SNS/SQS for worker queue instead of polling
5. **Multi-Region**: Replicate S3 bucket and DynamoDB table for global performance
6. **Advanced Search**: Elasticsearch or DynamoDB GSI for full-text search on titles/tags
7. **Progress Tracking**: WebSocket or Server-Sent Events for real-time transcode progress
8. **Rate Limiting**: API Gateway or Express middleware to prevent abuse
9. **Cost Optimization**: S3 Intelligent-Tiering, DynamoDB On-Demand billing

---

## Conclusion

This architecture demonstrates a **production-ready, cloud-native video processing platform** that leverages AWS managed services for scalability, security, and reliability. The **stateless design** ensures seamless horizontal scaling, while **caching** and **presigned URLs** optimize performance and cost. The **background worker** pattern decouples compute-heavy transcoding from API latency, enabling a responsive user experience.

For detailed API documentation, see [API_REFERENCE.md](./API_REFERENCE.md).
