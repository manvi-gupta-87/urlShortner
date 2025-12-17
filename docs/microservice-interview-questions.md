# Microservices Interview Questions & Answers

**Created:** November 10, 2025
**Purpose:** Quick reference for microservices interview preparation
**Level:** Senior Engineer (10 YOE)

---

## 📚 Table of Contents

1. [Service Discovery & Configuration](#service-discovery--configuration)
2. [Zero-Downtime Migration](#zero-downtime-migration)
3. [Database Strategies](#database-strategies)
4. [Resilience Patterns](#resilience-patterns)
5. [Traffic Management](#traffic-management)
6. [API Gateway & Service Mesh](#api-gateway--service-mesh)
7. [Reactive Programming](#reactive-programming)
8. [Monitoring & Observability](#monitoring--observability)
9. [Build & Deployment](#build--deployment) - Docker JVM Optimizations
10. [Kubernetes & Helm Deployment](#kubernetes--helm-deployment)
11. [Real Interview Scenarios](#real-interview-scenarios)
12. [Quick Interview Tips](#quick-interview-tips)
13. [Shared Library Architecture](#shared-library-architecture) - **NEW** Design principles & debugging

---

## Service Discovery & Configuration

### Q1: Is Eureka still used in industry?

**Short Answer:**

Eureka is **declining** in usage. Most companies now use:

| Technology | Market Share | Status |
|------------|-------------|--------|
| **Kubernetes DNS** | 70% | ✅ Standard |
| **Consul** | 15% | ✅ Active |
| **Eureka** | 10% | ⚠️ Maintenance |
| **Service Mesh (Istio)** | 5% | ✅ Enterprise |

**Why declining?**
- ❌ Requires separate server to manage
- ❌ Not cloud-native (designed for VMs)
- ❌ Kubernetes has built-in DNS-based discovery
- ❌ Netflix stopped active development

**Strong Interview Answer:**
> "Eureka was popular in 2015-2018 when Netflix open-sourced it, but modern microservices primarily use Kubernetes native service discovery. K8s DNS resolves service names automatically without needing a separate registry. For my learning project, I used Eureka because it's educational and well-documented, but in production I'd recommend Kubernetes DNS for cloud deployments or Consul for multi-cloud environments."

---

### Q2: What is the difference between Config Server and Eureka?

**Short Answer:**

They solve different problems:

| Aspect | Config Server | Eureka |
|--------|--------------|--------|
| **Purpose** | Store static configuration | Dynamic service discovery |
| **Contains** | DB URLs, API keys, feature flags | Service locations and health |
| **Updates** | Manual (requires restart) | Automatic (real-time) |
| **Registration** | Define URLs in config files | Services self-register |
| **Health checks** | ❌ No | ✅ Yes (heartbeats) |
| **Load balancing** | ❌ Manual | ✅ Automatic |

**Strong Interview Answer:**
> "Config Server stores centralized configuration like database URLs and API keys in a Git repository. It's static - you need to update config and restart services. Eureka is for dynamic service discovery - services automatically register their location and health status at runtime. Modern systems use Kubernetes ConfigMaps for configuration and K8s DNS for service discovery, eliminating the need for both."

---

### Q3: What's the difference between Eureka, Consul, and Kubernetes DNS?

**Detailed Comparison:**

| Feature | Eureka | Consul | Kubernetes DNS |
|---------|--------|--------|----------------|
| **Released** | 2012 | 2014 | 2015+ |
| **Status** | ⚠️ Maintenance mode | ✅ Active development | ✅ Standard |
| **Setup complexity** | Medium (separate server) | Medium (separate server) | Low (built-in) |
| **Multi-datacenter** | ❌ Poor support | ✅ Excellent | ⚠️ Complex (federation) |
| **Health checks** | ✅ Heartbeat only | ✅ HTTP/TCP/Script | ✅ Liveness/Readiness |
| **Service mesh** | ❌ No | ✅ Yes (Connect) | ✅ Yes (Istio/Linkerd) |
| **Key-value store** | ❌ No | ✅ Yes | ✅ Yes (etcd) |
| **Use case** | Legacy Java apps | Multi-cloud | Kubernetes-native |

**Strong Interview Answer:**
> "Eureka is Netflix's legacy solution from 2012, now in maintenance mode since 2018. Consul by HashiCorp is more modern with excellent multi-datacenter support and is popular for multi-cloud deployments. Kubernetes DNS is the current industry standard - it's built-in, requires no separate server, and uses native K8s Service objects. For new projects on Kubernetes, I'd use native DNS. For bare-metal or multi-cloud, Consul is the better choice."

---

## Zero-Downtime Migration

### Q4: How do you migrate a monolith to microservices without downtime?

**Short Answer:**

Use **Strangler Fig Pattern** with gradual rollout:

**Steps:**

1. **Build** microservice alongside monolith (both running)
2. **Deploy** routing layer with feature flags (Redis-backed)
3. **Canary release** starting at 10% traffic
4. **Monitor** error rates and latency in Grafana
5. **Gradually increase** to 25% → 50% → 100% over 4-6 weeks
6. **Database migration** last (replication → dual writes → separate DBs)
7. **Rollback** instant via feature flag toggle

**Architecture Evolution:**

```
Week 1: Monolith (90%) + Auth Service (10%)
Week 4: Monolith (0% - retired) + Auth Service (100%)
Total: Zero downtime
```

**Strong Interview Answer:**
> "I'd use the strangler fig pattern to incrementally migrate functionality. First, deploy the Auth microservice alongside the monolith with feature flags in the API Gateway for traffic routing. Start with a 10% canary deployment, monitoring error rates and latency in Prometheus/Grafana. Gradually increase to 25%, 50%, 75%, 100% over 4-6 weeks based on metrics. Database separation happens last - start with replication, then dual writes via event-driven sync with Kafka, finally cut over to separate databases. This approach provides zero downtime and instant rollback capability via feature flag toggles, similar to Netflix's 7-year migration."

---

### Q5: Can you use feature flags AND canary deployments together?

**Short Answer:**

**YES!** They're complementary and provide defense in depth.

**Different Purposes:**

| Aspect | Feature Flags | Canary Deployments |
|--------|--------------|-------------------|
| **Controls** | WHERE traffic goes (monolith vs microservice) | WHICH VERSION (v1.0 vs v2.0) |
| **Layer** | Application routing logic | Infrastructure/deployment |
| **Granularity** | User-level (specific users) | Traffic-level (% of all traffic) |
| **Rollback speed** | Instant (<1 sec) | 1-2 minutes |
| **Use case** | Migration, A/B testing | Version rollout, safety |

**Two Safety Nets:**

1. **Feature flag rollback:** If entire microservice is broken → toggle to 0% (instant)
2. **Canary rollback:** If just the new version has bugs → scale down canary (1-2 min)

**Strong Interview Answer:**
> "Absolutely, and it's industry best practice for defense in depth. Feature flags control application-layer routing - whether traffic goes to the monolith or microservice, with instant rollback and user-level granularity. Canary deployments operate at the infrastructure layer - gradually rolling out new versions of the same service with automated rollback based on metrics. Together they give two safety nets: if the entire microservice fails, toggle the feature flag. If just the new version has issues, scale down the canary. Netflix uses this exact approach - Zuul with feature flags plus Red/Black deployments to deploy hundreds of times daily."

---

### Q6: How do feature flags control 10% / 90% traffic split?

**Short Answer:**

**Algorithm:** Consistent hash-based bucketing

```java
public boolean isEnabled(String flagName, String userId) {
    // Get target percentage from Redis (e.g., 10)
    int targetPercentage = redis.get("feature:" + flagName + ":percentage");

    // Hash userId to get bucket 0-99
    int userBucket = Math.abs(userId.hashCode() % 100);

    // If bucket < percentage, enable
    return userBucket < targetPercentage;
}
```

**Example:**
- Flag = 10%
- user_grace → hash = 8 → 8 < 10 → ✅ Microservice
- user_alice → hash = 90 → 90 < 10 → ❌ Monolith

**Key Properties:**

1. **Deterministic:** Same user always gets same route (not random)
2. **Gradual rollout:** Increase percentage over time (10% → 50% → 100%)
3. **No user lists:** Hash function automatically distributes evenly
4. **Instant changes:** Update percentage in Redis, no restart needed

**Strong Interview Answer:**
> "Feature flags use consistent hashing to bucket users. I hash the userId modulo 100 to get a bucket from 0-99, then compare it to the target percentage stored in Redis. For example, at 10%, users in buckets 0-9 go to the microservice, 10-99 go to the monolith. This is deterministic - the same user always gets the same route, providing consistent UX. When I increase the percentage to 50%, buckets 0-49 now route to the microservice. The hash function distributes users evenly without maintaining explicit user lists, and I can change the percentage in Redis for instant rollout without restarting services."

---

## Database Strategies

### Q7: Do microservices need separate databases?

**Short Answer:**

**True microservices:** 1 service = 1 database instance

**Reality:** Many companies use pragmatic middle-ground approaches.

**Database Separation Levels:**

| Level | Setup | Your Company | True Microservices | Rating |
|-------|-------|--------------|-------------------|--------|
| **Instance** | 1 shared PostgreSQL | ✅ Common | ❌ Should be N separate | 5/10 |
| **Schema** | 1 shared schema | ✅ Common | ❌ Should be N schemas | 5/10 |
| **Tables** | Each service owns tables | ✅ Good | ✅ Good | 8/10 |
| **Write access** | Only to owned tables | ✅ Correct | ✅ Correct | 10/10 |
| **Read access** | Can read any table | ❌ Anti-pattern | ❌ Should use APIs | 3/10 |

**Shared DB Issues:**

❌ **Single point of failure:** 1 DB down = all services down
❌ **Can't scale independently:** Can't scale just the URL service DB
❌ **Cross-service reads = tight coupling:** Schema changes break other services
❌ **Can't use different DB types:** All stuck with same technology

**Strong Interview Answer:**
> "True microservices should have separate database instances to ensure complete isolation and independent scaling. However, I've worked with a pragmatic middle-ground approach where 51 services shared one database with separate tables. While this was better than a monolithic shared database, it had significant limitations: single point of failure, couldn't scale databases independently, and cross-service reads created tight coupling that defeated the purpose of microservices. The proper approach follows Amazon's mandate: 'No direct database access between teams' - all communication via APIs. This enables independent deployments, technology choices per service, and true scaling independence."

---

### Q8: How do you handle database migration in microservices?

**Short Answer:**

**Phased approach (never "big bang"):**

| Week | Strategy | Monolith | Microservice | Notes |
|------|----------|----------|--------------|-------|
| 1-2 | **Shared DB** | Write & Read | Write & Read | Both use same DB |
| 3-4 | **Replication** | Write (master) | Read (replica) | Test read-only access |
| 5-6 | **Dual Write** | Write to both | Write to both | Preparation for cutover |
| 7-8 | **Event-Driven** | Publishes events | Consumes events | Async sync via Kafka |
| 9+ | **Separate DBs** | (retired) | Independent | Monolith gone |

**Strong Interview Answer:**
> "Database migration is the most complex part of microservices migration. I'd use a phased approach over 8-10 weeks. Start with both services sharing the database for lowest risk. Then set up replication so the microservice reads from a replica, validating it doesn't need write access yet. Next, implement dual writes - the microservice writes to both databases, or better yet, the monolith publishes events to Kafka that the microservice consumes for async synchronization. Finally, after all traffic is migrated and stable for several weeks, cut over to fully separate databases. Database separation happens last because it's the highest-risk, most irreversible change. This approach gives you multiple rollback points along the way."

---

## Resilience Patterns

### Q9: Is Hystrix still used in industry?

**Short Answer:**

**NO.** Hystrix was **deprecated by Netflix in November 2018** and is in maintenance mode only.

**Timeline:**

| Year | Status |
|------|--------|
| 2012 | Netflix releases Hystrix |
| 2016 | Peak popularity |
| **Nov 2018** | **Netflix announces deprecation** |
| 2020+ | Maintenance mode, security patches only |
| 2023+ | Legacy, incompatible with Spring Boot 3 |

**Replacement:** **Resilience4j** (modern, lightweight, active development)

**Comparison:**

| Feature | Hystrix (Deprecated) | Resilience4j (Modern) |
|---------|---------------------|----------------------|
| **Status** | ❌ Deprecated (2018) | ✅ Active development |
| **Architecture** | Thread pool isolation (heavy) | Decorator pattern (lightweight) |
| **Memory usage** | High (separate thread pools) | Low (no extra threads) |
| **Spring Boot 3** | ❌ Incompatible | ✅ Fully supported |
| **Metrics** | Hystrix Dashboard | Micrometer (Prometheus) |
| **Circuit breaker** | ✅ Yes | ✅ Yes |
| **Retry** | Limited | ✅ Advanced (exponential backoff) |
| **Rate limiting** | ❌ No | ✅ Yes (built-in) |
| **Bulkhead** | Thread pools | ✅ Semaphore-based |

**Strong Interview Answer:**
> "My current company still uses Hystrix, but I'm aware Netflix deprecated it in November 2018. For personal projects, I use Resilience4j - the modern replacement. Resilience4j is more lightweight, using decorator patterns instead of Hystrix's heavyweight thread pool isolation, resulting in significantly better performance and lower memory usage. It also integrates natively with Micrometer for Prometheus metrics, which is the industry standard for observability. Additionally, Resilience4j is compatible with Spring Boot 3, while Hystrix is not. For companies still on Hystrix, I'd recommend planning a migration to Resilience4j to avoid future compatibility and security issues."

---

## Traffic Management

### Q10: What metrics do you monitor during migration?

**Short Answer:**

**Four Critical Categories:**

**1. Traffic Metrics**
- Request rate to verify traffic split matches target

**2. Error Metrics**
- Compare 4xx/5xx rates between stable and canary
- Alert if canary error rate exceeds stable by 50%

**3. Performance Metrics**
- P50, P95, P99 latency comparison
- Alert on 20%+ latency regression

**4. Business Metrics**
- User registrations, order completion rates, revenue

**Strong Interview Answer:**
> "I'd track four categories: Traffic metrics to verify the split matches the target - if I set 10% canary, I need to confirm 10% of requests actually hit it. Error metrics comparing 4xx/5xx rates between canary and stable, with alerts if canary errors exceed stable by 50%. Performance metrics tracking P50, P95, and P99 latency, alerting on 20% regression. And critically, business metrics like user signups and order completion rates to catch issues that don't appear in technical metrics. I'd use Prometheus for collection, Grafana for dashboards, and PagerDuty for alerting with automated rollback triggers if error rate crosses thresholds."

---

### Q11: What if the microservice fails in production?

**Short Answer:**

**Immediate Response (< 30 seconds):**

```bash
# Toggle feature flag to 0% → instant rollback
curl -X PUT "http://gateway/admin/feature-flags/use-auth-microservice/percentage?percentage=0"
```

**Within 5 Minutes:**
- Check **Grafana** dashboards for metrics
- Review **Kibana** logs for error messages
- Analyze **Zipkin** distributed traces

**Within 30 Minutes:**
- If hotfix available: Deploy to 5% canary first
- If not: Keep flag at 0% and investigate offline

**Strong Interview Answer:**
> "This is why feature flags are critical for production safety. My immediate response would be to toggle the feature flag to 0% to route all traffic back to the monolith - no deployment needed, instant rollback in under 1 second. Then I'd investigate using our observability stack: Grafana for metrics to identify when errors started, Kibana for logs to see error messages, and Zipkin for distributed traces to understand which service in the chain failed. Within 5 minutes I'd have the blast radius contained and root cause identified. If a hotfix is available, I'd deploy it to a 5% canary first to validate. This is exactly why we don't jump to 100% immediately - canary deployments with feature flags provide multiple rollback mechanisms and limit blast radius."

---

### Q11.1: What is Active-Active setup with GSLB?

**Short Answer:**

**Active-Active** = Running your application in **multiple data centers simultaneously**, where all data centers actively serve traffic.

**GSLB (Global Server Load Balancer)** = DNS-based intelligent router that directs users to the best data center.

**Architecture:**

```
User Request
    ↓
GSLB (DNS-based routing)
    ↓
Routes based on: Location, Health, Load, Performance
    ↓
┌─────────────┬─────────────┬─────────────┐
│   US-East   │   US-West   │   Europe    │
│   (Active)  │   (Active)  │   (Active)  │
└─────────────┴─────────────┴─────────────┘
```

**GSLB Routing Strategies:**

| Strategy | How it Works | Example |
|----------|-------------|---------|
| **Geographic** | Route to nearest DC | Mumbai user → India DC |
| **Health-based** | Route to healthy DCs only | DC fails → auto-switch to backup |
| **Load-based** | Route to DC with capacity | 80% full DC → lower priority |
| **Performance-based** | Route to fastest DC | 50ms DC preferred over 200ms DC |

**Active-Active vs Active-Passive:**

| Aspect | Active-Active | Active-Passive |
|--------|---------------|----------------|
| **Traffic** | All DCs serve traffic | Only primary serves |
| **Failover** | Instant (already active) | 30-60 seconds |
| **Utilization** | High (all DCs used) | 50% (backup idle) |
| **Latency** | Low (nearest DC) | Variable (single location) |
| **Cost** | Higher | Lower |
| **Use Case** | Global apps (Netflix, Amazon) | DR backup only |

**Benefits:**

- **Low latency**: Users routed to nearest DC (5ms vs 250ms)
- **High availability**: If one DC fails, others handle traffic instantly
- **No downtime**: All DCs running continuously
- **99.99% uptime**: ~43 minutes downtime/year

**Example - Netflix:**

```
User in Mumbai opens Netflix
    ↓
GSLB: Check Mumbai DC (healthy ✓)
    ↓
Route to Mumbai DC (5ms latency)

If Mumbai DC fails:
    ↓
GSLB: Detect failure within 10 seconds
    ↓
Auto-route to Singapore DC (20ms latency)
```

**Popular GSLB Technologies:**

- **AWS Route 53** - Health checks + geographic routing
- **Cloudflare Load Balancer** - Global CDN with GSLB
- **Azure Traffic Manager** - Azure's GSLB service
- **F5 BIG-IP DNS** - Enterprise hardware solution

**Strong Interview Answer:**
> "Active-Active with GSLB is the industry standard for global applications. It means running your application in multiple data centers simultaneously, where all DCs actively serve traffic. GSLB is a DNS-based load balancer that intelligently routes users to the best data center based on geographic location, health status, load, and performance. For example, Netflix uses this - a user in Mumbai gets routed to the India DC for low latency, but if that DC fails, GSLB automatically redirects to Singapore DC within seconds. This provides instant failover, low latency worldwide, and 99.99% uptime. Companies like Amazon and Google use AWS Route 53 or similar GSLB solutions. It's more expensive than Active-Passive because all DCs are running, but it's essential for global user experience."

---

### Q11.2: What are the issues with Active-Passive approach?

**Short Answer:**

Active-Passive has **critical limitations** that make it unsuitable for modern global applications:

**Key Issues:**

| Issue | Impact | Example |
|-------|--------|---------|
| **50% Resource Waste** | Passive DC sits idle while costing money | Paying for 200 servers, using only 100 |
| **Slow Failover (30-60s)** | Users experience downtime during failure | DNS propagation + app startup delay |
| **High Latency for Remote Users** | Single DC location | Singapore user → US DC = 250ms latency |
| **Untested Failover** | Passive DC may have stale configs/data | Discover issues during actual disaster |
| **Limited Capacity** | 50% capacity during failover | 100K req/sec → 50K req/sec (may need load shedding) |
| **No Load Distribution** | Primary can overload while passive idle | Black Friday: Primary struggles, passive unused |

**Failover Comparison:**

```
Active-Passive:
DC Fails → Monitoring detects (5s) → DNS update (10s) →
DNS propagates (30-60s) → Scale up passive (30s)
= 1 minute downtime

Active-Active:
DC Fails → GSLB health check (10s) → Instant reroute
= 10 seconds, zero downtime
```

**When Active-Passive is Still Acceptable:**

- ✅ Small companies (can't afford multi-DC)
- ✅ Internal tools (1 min downtime acceptable)
- ✅ Non-critical systems (logs, batch jobs)
- ✅ Regulatory constraints (data must stay in one region)

**Strong Interview Answer:**
> "Active-Passive has several critical issues. First, it wastes 50% of infrastructure - you're paying for a passive DC that serves no traffic. Second, failover is slow at 30-60 seconds due to DNS propagation and application startup time. Third, global users experience high latency because all traffic goes to one location - a Singapore user hitting a US-based primary DC gets 250ms latency instead of 20ms with a local DC. Fourth, there's untested failover risk - the passive DC might have stale configurations or data issues you only discover during an actual disaster. Finally, you have limited capacity during failover since the passive DC typically has 50% capacity. This is why modern companies like Netflix and Amazon use Active-Active with GSLB - it provides instant failover, low latency worldwide, and no wasted resources. Active-Passive is only acceptable for small companies, internal tools, or systems where regulatory constraints require data to stay in one region."

---

### Q11.3: How is data synchronized between datacenters in Active-Active and Active-Passive setups?

**Short Answer:**

Data synchronization complexity is the **biggest challenge** in multi-datacenter architectures.

**Active-Passive Synchronization (Simpler):**

```
Primary DC                    Passive DC
┌──────────────┐             ┌──────────────┐
│ Master DB    │ ──────────> │ Replica DB   │
│ (Read/Write) │   One-way   │ (Read-only)  │
└──────────────┘             └──────────────┘
```

| Method | How It Works | Lag | Use Case |
|--------|--------------|-----|----------|
| **Async Replication** | Write to primary, replicate later | 1-60 seconds | Most systems |
| **Sync Replication** | Write to both, wait for confirmation | 0 seconds (slower writes) | Financial systems |
| **Log Shipping** | Ship transaction logs periodically | Minutes to hours | Legacy DR |

**Active-Active Synchronization (Complex):**

**1. Multi-Master Replication**
```
US DC                         EU DC
┌──────────────┐             ┌──────────────┐
│ Master DB    │ <─────────> │ Master DB    │
│ (Read/Write) │  Bi-Sync    │ (Read/Write) │
└──────────────┘             └──────────────┘

Conflict: Both DCs update same record simultaneously
Resolution: Last Write Wins, CRDT, or App-level merge
```

**2. Regional Sharding (Netflix Model)**
```
US DC: Owns US user data (master)
EU DC: Owns EU user data (master)
Each DC replicates to others (read-only)
Result: No conflicts (different data ownership)
```

**3. Event Sourcing with Kafka**
```
All changes → Kafka events → All DCs consume events
Result: Eventual consistency (1-5 second lag)
Example: Uber uses this for trip updates
```

**Conflict Resolution Strategies:**

| Strategy | Description | Example |
|----------|-------------|---------|
| **Last Write Wins (LWW)** | Latest timestamp wins | Price update: $200 (later) beats $100 |
| **Causality Tracking** | Vector clocks determine order | Cassandra, Riak |
| **Application Merge** | Code merges both updates | Shopping cart: merge items |
| **Regional Authority** | One DC owns specific data | US DC owns US customers |

**Real-World Examples:**

- **Netflix**: Cassandra multi-master, eventual consistency, 1-2 sec lag
- **Amazon DynamoDB**: Multi-region tables, async replication, <1 sec lag
- **Google Spanner**: Synchronous with atomic clocks, 200-500ms writes
- **Banks**: Active-Passive, sync replication, zero data loss

**Strong Interview Answer:**
> "Data synchronization is fundamentally different between Active-Passive and Active-Active. Active-Passive uses simple one-way replication from master to replica, typically with 1-60 seconds of lag using asynchronous replication, or zero lag with synchronous replication at the cost of slower writes. The challenge is potential data loss if the primary fails before replication completes. Active-Active is much more complex because you have multiple masters accepting writes simultaneously. This creates the conflict problem - what happens when two datacenters update the same record at the same time? Companies solve this with different strategies: Netflix uses Last Write Wins with Cassandra where the latest timestamp wins, companies like Uber use event sourcing with Kafka where all changes are events consumed by all datacenters, and some use regional sharding where US users are owned by the US datacenter and EU users by the EU datacenter to avoid conflicts entirely. Google Spanner takes a different approach using atomic clocks and synchronous replication for strong consistency, but this adds 200-500ms write latency. The choice depends on your consistency requirements - financial systems need sync replication and zero data loss, while social media can tolerate 1-5 second eventual consistency for better performance."

---

### Q11.4: Why does API Gateway need JWT validation? Shouldn't only Auth-Service handle JWT?

**Short Answer:**

API Gateway **validates** JWT tokens, Auth-Service **generates** them. This is called **"Authentication at the Edge"** pattern.

**The Two Roles:**

| Service | Has JwtUtil? | Purpose |
|---------|-------------|---------|
| **Auth-Service** | ✅ Yes | **Generate** tokens when user logs in |
| **API Gateway** | ✅ Yes | **Validate** tokens on every request |
| **URL-Service** | ❌ No | Trusts Gateway already validated |
| **Analytics-Service** | ❌ No | Trusts Gateway already validated |

**The Flow:**

```
1. User Login (Token Generation)
   Client → API Gateway → Auth-Service
   Auth-Service: Generates JWT with secret key
   Returns: { "token": "eyJhbGc..." }

2. Every Other Request (Token Validation)
   Client → API Gateway (validates token locally)
         → URL-Service (if valid)

   API Gateway blocks invalid tokens before reaching services
```

**Why Not Call Auth-Service for Validation?**

**Bad Approach (Anti-pattern):**
```
Every Request:
Client → API Gateway → Auth-Service (validate token?)
                    → URL-Service (actual request)

Problems:
❌ Auth-Service becomes bottleneck (1000 req/sec = 1000 validations)
❌ Extra network hop adds 50-100ms latency
❌ Auth-Service can go down, blocking all requests
```

**Good Approach (Industry Standard):**
```
Every Request:
Client → API Gateway (validate locally with JwtUtil)
      → URL-Service (if valid)

Benefits:
✅ Fast validation (<1ms, just cryptographic signature check)
✅ Auth-Service only handles login/register
✅ No bottleneck, high performance
```

**Key Insight: JWT Tokens are Self-Contained**

JWT tokens are **cryptographically signed**:
- Anyone with the **secret key** can validate them
- No database lookup needed
- No network call to Auth-Service needed
- Just verify the signature matches

**Both services use the SAME secret key:**
```yaml
# Auth-Service application.yml
jwt:
  secret: mySecretKey123  # Signs token with this

# API Gateway application.yml
jwt:
  secret: mySecretKey123  # Verifies signature with same secret
```

**Comparison: With vs Without Gateway Validation**

| Approach | Where JWT Validation Happens | Performance |
|----------|----------------------------|-------------|
| **Without Gateway** | Every microservice validates | Each service needs JwtUtil (code duplication) |
| **With Gateway (Correct)** | Only Gateway validates | Services trust Gateway, no duplication |

**Real-World Example: Netflix**

```
Netflix Architecture:
- Auth Service: Issues JWT tokens (login/signup only)
- API Gateway (Zuul): Validates JWT on EVERY request
- 50+ Microservices: Don't validate JWT (Gateway already did)

Result:
- 10,000 requests/sec validated at Gateway
- Zero load on Auth-Service (only login/register traffic)
- Microservices focus on business logic
```

**What Happens if Gateway Doesn't Validate?**

```
Without Gateway Validation:
- URL-Service needs JwtUtil ❌
- Analytics-Service needs JwtUtil ❌
- User-Service needs JwtUtil ❌
- Payment-Service needs JwtUtil ❌
- 50 other services need JwtUtil ❌

Problems:
- Code duplication across 50 services
- Each service must handle invalid tokens
- Inconsistent validation logic
- Security vulnerabilities if one service forgets
```

**Strong Interview Answer:**
> "API Gateway needs JWT validation because of the 'Authentication at the Edge' pattern - we validate authentication once at the entry point rather than in every microservice. While Auth-Service generates JWT tokens during login, the API Gateway validates them on every subsequent request. This is efficient because JWT tokens are self-contained and cryptographically signed - anyone with the secret key can validate them locally without calling Auth-Service. If we had to call Auth-Service for validation on every request, it would become a bottleneck handling thousands of validation requests per second and add 50-100ms latency per request. Instead, the Gateway validates tokens in under 1ms using cryptographic signature verification. This is how Netflix and other companies handle millions of requests - Auth-Service only handles login/register traffic, while the Gateway validates all subsequent requests. Both services share the same JWT secret key, so the Gateway can verify that tokens were signed by Auth-Service. The downstream microservices like URL-Service and Analytics-Service don't need JWT validation at all - they trust that if a request reached them through the Gateway, it's already authenticated. This eliminates code duplication and ensures consistent security across all services."

---

## API Gateway & Service Mesh

### Q14: What is the difference between API Gateway and Service Mesh?

**Short Answer:**

They serve **different layers** and are **complementary**, not competing solutions.

| Aspect | API Gateway | Service Mesh |
|--------|-------------|--------------|
| **Traffic Direction** | North-South (External → Services) | East-West (Service ↔ Service) |
| **Purpose** | Single entry point for clients | Inter-service communication management |
| **Layer** | Edge/Perimeter | Internal network |
| **Main Functions** | Auth, rate limiting, routing, API versioning | mTLS, observability, traffic management, resilience |
| **Users** | External clients (mobile, web, APIs) | Internal services only |
| **Examples** | Kong, AWS API Gateway, Spring Cloud Gateway | Istio, Linkerd, Consul Connect |
| **Code Changes** | May require endpoint definitions | Zero code changes |

**Visual Representation:**

```
[Mobile App]  [Web Browser]  [Third-party API]
      ↓              ↓                ↓
═══════════════════════════════════════════════
        API GATEWAY (North-South)
═══════════════════════════════════════════════
              ↓
┌─────────────────────────────────────────────┐
│         SERVICE MESH (East-West)            │
│                                             │
│  [url-service] ←──────→ [analytics-service] │
│       ↕                        ↕            │
│  [auth-service] ←──────→ [user-service]     │
└─────────────────────────────────────────────┘
```

**Strong Interview Answer:**
> "API Gateway and Service Mesh solve different problems and are used together in production systems. API Gateway sits at the edge, handling north-south traffic from external clients to services - it's the single entry point for authentication, rate limiting, API versioning, and request routing. Service Mesh operates internally, managing east-west traffic between services - it provides automatic mTLS encryption, distributed tracing, circuit breaking, and retry logic without code changes. For example, in our URL shortener, the API Gateway would handle mobile app requests and route them to the appropriate microservice, while the Service Mesh would secure and monitor the call from url-service to analytics-service. Companies like Uber and Airbnb use both: Kong/Zuul at the edge and Istio/Linkerd internally."

---

### Q14.1: Where does routing actually happen in modern API Gateway architecture?

**Short Answer:**

**Common Misconception:** Developers expect routing code in the Gateway application.
**Reality:** Routing is **externalized** from application code.

**What API Gateway Code Actually Contains:**

Modern Gateway applications focus on **cross-cutting concerns**, not routing:
- Authentication and authorization (token validation, permissions)
- Security (fraud detection, rate limiting, threat protection)
- Configuration management
- API discovery and metadata
- Request validation

**Where Routing Really Lives:**

| Approach | Implementation | Managed By |
|----------|---------------|------------|
| **Declarative Config** | YAML/properties files | DevOps |
| **Cloud Load Balancers** | AWS ALB, Azure Gateway | Platform team |
| **Kubernetes Ingress** | Ingress controller YAML | Infrastructure team |
| **API Management Platform** | Apigee, Kong, MuleSoft | API team |
| **Service Mesh** | Istio VirtualService, Linkerd | DevOps/SRE |

**Why This Separation?**

**Benefits:**
- Change routes without code changes or redeployment
- Real-time configuration updates
- DevOps manages routing independently
- Developers focus on business logic and security

**Key Principle:**
Routing = **Deployment Concern** (infrastructure)
Security/Validation = **Development Concern** (application code)

**Example: Enterprise Bank Architecture**

```
Client Request
    ↓
[Load Balancer/Ingress] ← Routes based on path (infrastructure)
    ↓
[Gateway Controller] ← Validates token, checks permissions (code)
    ↓
[Backend Services]
```

**Strong Interview Answer:**
> "In modern architectures, routing is externalized from the Gateway application code. The Gateway controller focuses on cross-cutting concerns like authentication, authorization, and security validation. Actual routing happens through declarative configuration - YAML files for Spring Cloud Gateway, Kubernetes Ingress controllers, cloud load balancers like AWS ALB, or API management platforms like Apigee. This separation means route changes don't require code changes or redeployment. For example, at companies like Deutsche Bank, you'll see Gateway controllers with methods for token validation and permission checks, but no routing logic - that's managed separately by DevOps through infrastructure configuration. This is the current industry standard because routing is a deployment concern, not a development concern."

---

### Q15: What is a Service Mesh and why do we use it?

**Short Answer:**

**Service Mesh** is an **infrastructure layer** that handles service-to-service communication with automatic security, observability, and resilience.

**Why Use It?**

**Without Service Mesh:**
```java
// Every service needs this duplicated code
@Configuration
public class SecurityConfig {
    // Setup SSL/TLS manually
    // Configure retries manually
    // Add tracing headers manually
    // Implement circuit breakers manually
}
```

**With Service Mesh:**
```yaml
# One-time configuration - applies to ALL services
apiVersion: security.istio.io/v1beta1
kind: PeerAuthentication
spec:
  mtls:
    mode: STRICT  # All services auto-encrypted
```

**Key Benefits:**

| Problem | Without Service Mesh | With Service Mesh |
|---------|---------------------|-------------------|
| **Security** | Write mTLS code in every service | Automatic encryption (zero code) |
| **Retries** | Implement in every service | Configured once, applies everywhere |
| **Tracing** | Manually propagate trace IDs | Automatic distributed tracing |
| **Circuit Breaking** | Code circuit breakers per service | Infrastructure-level, consistent |
| **Canary Deployments** | Complex custom logic | Simple config (10% v1, 90% v2) |
| **Observability** | Different logging per team | Unified metrics across all services |

**Popular Service Mesh Tools:**

| Tool | Developed By | Market Share | Best For |
|------|--------------|--------------|----------|
| **Istio** | Google/IBM | 60% | Full-featured, enterprise |
| **Linkerd** | Buoyant | 25% | Lightweight, simple |
| **Consul Connect** | HashiCorp | 10% | Multi-cloud, hybrid |
| **AWS App Mesh** | Amazon | 5% | AWS-native |

**Strong Interview Answer:**
> "Service Mesh is an infrastructure layer that manages service-to-service communication without requiring code changes. It solves the problem of duplicating security, resilience, and observability code across dozens of microservices. For example, instead of writing mTLS configuration in every service, I configure Istio once and all services automatically get encrypted communication. It also provides automatic distributed tracing, retry logic with exponential backoff, circuit breakers, and canary deployments via simple YAML configuration. This is critical at scale - companies like Uber and Lyft use service mesh to manage thousands of microservices. However, I wouldn't use it for small projects with 2-3 services due to operational complexity. The sweet spot is 10+ microservices where the benefits outweigh the infrastructure overhead."

---

### Q16: Can we use Service Mesh along with REST API and Kafka?

**Short Answer:**

**YES!** Service Mesh works **on top of** existing communication protocols, not as a replacement.

**How They Work Together:**

**Service Mesh + REST:**
```java
// Your code - NO CHANGES NEEDED
@FeignClient(name = "analytics-service")
public interface AnalyticsServiceClient {
    @GetMapping("/api/v1/analytics/stats")
    UrlAnalyticsResponse getStats(@RequestParam Long urlId);
}

// Service Mesh automatically adds:
// - mTLS encryption
// - Distributed tracing headers
// - Retry logic (3 attempts)
// - Circuit breaking
// - Metrics collection
```

**Service Mesh + Kafka:**
```java
// Your code - NO CHANGES NEEDED
@Service
public class ClickTrackingService {
    public void trackClick(ClickEvent event) {
        kafkaTemplate.send("url-clicks", event);
    }
}

// Service Mesh automatically adds:
// - Encrypted connection to Kafka
// - Connection monitoring
// - Access control policies
// - Network-level metrics
```

**Architecture Layers:**

```
┌─────────────────────────────────────┐
│  Application Code (REST/Kafka)     │ ← You write this
├─────────────────────────────────────┤
│  Communication Protocol (HTTP/TCP)  │ ← How data moves
├─────────────────────────────────────┤
│  Service Mesh (Istio/Linkerd)      │ ← Infrastructure enhancement
├─────────────────────────────────────┤
│  Network Layer (TCP/IP)             │ ← Physical network
└─────────────────────────────────────┘
```

**What Service Mesh Does NOT Replace:**

| You Still Need | Service Mesh Does NOT Replace |
|----------------|------------------------------|
| REST API calls (Feign, RestTemplate) | ✅ Enhances with security/retries |
| Kafka producers/consumers | ✅ Enhances with encryption/monitoring |
| API endpoints (@GetMapping) | ✅ Enhances with observability |
| Business logic | ✅ Infrastructure-only |

**Strong Interview Answer:**
> "Absolutely! Service Mesh is an infrastructure enhancement, not a communication protocol replacement. You still write REST API calls using Feign or RestTemplate, and use Kafka for async messaging. The service mesh operates at the network layer, transparently intercepting these calls to add mTLS encryption, distributed tracing, retries, and circuit breaking without any code changes. For example, when my url-service calls analytics-service via Feign, the service mesh proxy intercepts the HTTP request, encrypts it with mTLS, adds trace headers, and monitors latency - all invisible to my application code. The same applies to Kafka connections. This separation of concerns is powerful: developers focus on business logic, while infrastructure teams configure security and resilience policies centrally."

---

### Q17: What do Java developers need to know about Service Mesh?

**Short Answer:**

**You don't write code for service mesh** - it's infrastructure. But you should know:

**1. Zero Code Changes Required**
```java
// This code works identically with or without service mesh
@FeignClient(name = "analytics-service")
public interface AnalyticsServiceClient {
    @GetMapping("/api/v1/analytics/stats")
    UrlAnalyticsResponse getStats(@RequestParam Long urlId);
}
```

**2. You ARE Responsible For:**

| Your Responsibility | Why It Matters |
|---------------------|----------------|
| **Health check endpoints** | Service mesh routes traffic based on health |
| **Proper error handling** | Don't rely 100% on mesh retries |
| **Timeouts in code** | Defense in depth with mesh timeouts |
| **Propagating trace headers** | For distributed tracing to work |
| **Graceful degradation** | Circuit breakers can fail fast |

**Health Check Example:**
```java
@RestController
public class HealthController {

    @GetMapping("/health")
    public ResponseEntity<String> health() {
        return ResponseEntity.ok("UP");
    }

    @GetMapping("/ready")
    public ResponseEntity<String> ready() {
        // Check DB connection, dependencies, etc.
        if (database.isConnected()) {
            return ResponseEntity.ok("READY");
        }
        return ResponseEntity.status(503).body("NOT_READY");
    }
}
```

**3. Debugging Changes:**

**Without Service Mesh:**
```
Error: Connection refused to analytics-service:8080
```

**With Service Mesh:**
```
Error: upstream connect error or disconnect/reset before headers
Circuit breaker: OPEN
Transport failure reason: connection timeout
```

**Action:** Check BOTH logs:
```bash
# Your app logs
kubectl logs my-service-pod -c my-service

# Service mesh sidecar logs
kubectl logs my-service-pod -c istio-proxy
```

**4. Performance Consideration:**

Service mesh adds **1-5ms latency** per request (proxy overhead)

```java
// Still implement timeouts
@FeignClient(name = "analytics-service")
public interface AnalyticsServiceClient {

    @GetMapping(value = "/api/v1/analytics/stats")
    UrlAnalyticsResponse getStats(
        @RequestParam Long urlId,
        @RequestHeader("x-request-timeout") @DefaultValue("5000") int timeout
    );
}
```

**5. Local Development:**

**Local (no service mesh):**
```yaml
# docker-compose.yml
services:
  url-service:
    ports: ["8081:8081"]
  analytics-service:
    ports: ["8082:8082"]
```

**Production (with service mesh):**
```yaml
# kubernetes deployment
metadata:
  annotations:
    sidecar.istio.io/inject: "true"
```

**Impact:** Test locally without mesh, but validate in staging WITH mesh.

**Strong Interview Answer:**
> "As a Java developer, I don't need to write code for service mesh - it's transparent infrastructure. However, I'm responsible for providing proper health check endpoints (/health and /ready) that the mesh uses for traffic routing. I still implement error handling, timeouts, and graceful degradation because defense in depth is critical - the mesh provides retries, but my code should handle failures appropriately. For debugging, I check both my application logs and the sidecar proxy logs since service mesh errors look different (e.g., 'circuit breaker OPEN' vs standard exceptions). I'm also aware that service mesh adds 1-5ms latency, which is usually negligible but important for tight latency requirements. Finally, I test locally without mesh but always validate in staging with mesh enabled, since network behavior differs between environments."

---

## Monitoring & Observability

### Q12: What's the difference between monitoring and observability?

**Short Answer:**

**Monitoring:** Known unknowns - tracking predefined metrics
**Observability:** Unknown unknowns - investigating unexpected issues

**Three Pillars of Observability:**

| Pillar | Purpose | Tools | Example |
|--------|---------|-------|---------|
| **Metrics** | Numbers over time | Prometheus, Grafana | CPU 80%, latency P99 |
| **Logs** | Event records | ELK, Splunk | "User 123 failed login" |
| **Traces** | Request flow | Zipkin, Jaeger | Request through 5 services |

**Strong Interview Answer:**
> "Monitoring is for known unknowns - I track predefined metrics like CPU, memory, error rates, and alert when they exceed thresholds. Observability is for unknown unknowns - when a complex, unexpected issue occurs, I need to investigate and understand the system's internal state. The three pillars are: metrics for aggregate trends, logs for detailed event records, and distributed traces for understanding request flow across services. In my URL shortener project, I use Prometheus for metrics, ELK for logs, and Zipkin for traces, giving me full observability to debug issues I couldn't have predicted."

---

## Build & Deployment

### Q13: What's the difference between executable JAR and library JAR?

**Short Answer:**

**Library JAR:** Contains reusable code for dependencies
**Executable JAR:** Standalone application that can be run directly

**Comparison:**

| Aspect | Library JAR | Executable JAR (Spring Boot) |
|--------|-------------|------------------------------|
| **Purpose** | Provide reusable code | Run standalone application |
| **Structure** | Standard JAR with classes | Fat JAR with nested dependencies |
| **Main class** | ❌ None | ✅ Required (e.g., AuthServiceApplication) |
| **Usage** | Added as dependency in POM | Run with `java -jar app.jar` |
| **Spring Boot plugin** | Skip repackaging (`<skip>true</skip>`) | Repackage as fat JAR |
| **Example** | shared-library-1.0.0.jar | auth-service-1.0.0.jar |
| **Size** | Small (~50KB) | Large (~50MB with all deps) |

**Library JAR Structure:**
```
shared-library-1.0.0.jar
├── com/urlshortener/dto/ErrorResponse.class
├── com/urlshortener/exception/...
└── META-INF/MANIFEST.MF (no Main-Class)
```

**Executable JAR Structure:**
```
auth-service-1.0.0.jar
├── BOOT-INF/
│   ├── classes/           # Your compiled code
│   └── lib/               # All dependencies (including shared-library)
├── org/springframework/boot/loader/  # Spring Boot loader
└── META-INF/MANIFEST.MF
    Main-Class: org.springframework.boot.loader.JarLauncher
    Start-Class: com.urlshortener.AuthServiceApplication
```

**Maven Configuration:**

```xml
<!-- Library JAR (shared-library) -->
<plugin>
    <groupId>org.springframework.boot</groupId>
    <artifactId>spring-boot-maven-plugin</artifactId>
    <configuration>
        <skip>true</skip>  <!-- Skip repackaging -->
    </configuration>
</plugin>

<!-- Executable JAR (auth-service) -->
<plugin>
    <groupId>org.springframework.boot</groupId>
    <artifactId>spring-boot-maven-plugin</artifactId>
    <!-- Default: repackage into executable JAR -->
</plugin>
```

**Common Build Error:**

When you forget `<skip>true</skip>` on a library:
```bash
[ERROR] Unable to find main class
```

**Why?** Spring Boot plugin tries to create executable JAR but library has no main class.

**Strong Interview Answer:**
> "Library JARs contain reusable code for other services to depend on - they're lightweight, contain only compiled classes, and can't be executed directly. Executable JARs, created by Spring Boot's repackaging plugin, are fat JARs that bundle your application code plus all dependencies in BOOT-INF/lib, making them standalone and runnable with `java -jar`. In our microservices project, the shared-library module is a library JAR that we add as a dependency to auth-service and url-service. Those service modules are executable JARs that can be deployed and run independently. The key is configuring the Spring Boot Maven plugin with `<skip>true</skip>` for library modules to prevent it from trying to create an executable JAR without a main class."

---

## Kubernetes & Helm Deployment

### Q19: How are microservices deployed in enterprise environments?

**Short Answer:**

**Modern Standard:** Kubernetes with Helm Charts for package management

**Deployment Stack:**

| Component | Technology | Purpose |
|-----------|-----------|---------|
| **Container Runtime** | Docker | Package applications with dependencies |
| **Orchestration** | Kubernetes (K8s) | Manage containers at scale |
| **Package Manager** | Helm Charts | Deploy and version K8s resources |
| **CI/CD** | GitHub Actions, Jenkins | Automate build and deployment |
| **Monitoring** | Grafana + New Relic/Datadog | Observability and APM |
| **Service Discovery** | K8s Service + DNS | Internal service communication |

**Typical Repository Structure:**

```
devops-cicd-pipeline/
├── helm/
│   ├── auth-service-helm/
│   │   ├── Chart.yaml
│   │   ├── values.yaml
│   │   └── templates/
│   ├── url-service-helm/
│   └── analytics-service-helm/
├── dockerfiles/
├── .github/workflows/
└── k8s/
```

**Why Kubernetes + Helm?**

| Feature | Benefit |
|---------|---------|
| **Auto-scaling** | Scale pods based on CPU/memory |
| **Self-healing** | Restart failed containers automatically |
| **Rolling updates** | Zero-downtime deployments |
| **Service discovery** | Built-in DNS for service-to-service calls |
| **Load balancing** | Distribute traffic across pods |
| **Config management** | ConfigMaps and Secrets |
| **Version control** | Helm manages releases and rollbacks |

**Strong Interview Answer:**
> "In enterprise environments like Deutsche Bank, microservices are deployed on Kubernetes using Helm charts for package management. Each microservice has its own Helm chart with templates for Deployments, Services, ConfigMaps, and Ingress resources. The deployment pipeline uses GitHub Actions to build Docker images, run tests, and deploy to Kubernetes clusters. Helm manages different environments (dev, staging, prod) using separate values files. This provides auto-scaling, self-healing, rolling updates, and easy rollbacks. Monitoring is handled by Grafana for metrics visualization and New Relic for application performance monitoring. The architecture is cloud-agnostic - it can run on AWS EKS, Azure AKS, or Google GKE."

---

### Q20: What is Helm and why do companies use it?

**Short Answer:**

**Helm** = Kubernetes Package Manager (like npm for Node.js, Maven for Java)

**What Helm Solves:**

**Without Helm (Manual K8s):**
```
❌ Manage 20+ YAML files per service
❌ Copy-paste configs for each environment
❌ Manual version tracking
❌ Complex rollbacks (reapply old YAMLs)
❌ No templating - hardcoded values
```

**With Helm:**
```
✅ One Chart = Complete application package
✅ Templates with variables
✅ Easy multi-environment deployment
✅ One-command install/upgrade/rollback
✅ Version history and rollbacks
```

**Helm Chart Structure:**

```
auth-service-helm/
├── Chart.yaml              # Chart metadata (name, version)
├── values.yaml            # Default configuration values
├── values-dev.yaml        # Dev environment overrides
├── values-prod.yaml       # Prod environment overrides
└── templates/
    ├── deployment.yaml    # Pod deployment template
    ├── service.yaml       # Service template
    ├── ingress.yaml       # Ingress template
    └── configmap.yaml     # Config template
```

**Deployment Commands:**

```bash
# Install to dev
helm install auth-service ./auth-service-helm -f values-dev.yaml

# Upgrade to new version
helm upgrade auth-service ./auth-service-helm

# Rollback to previous version
helm rollback auth-service 1

# List all releases
helm list
```

**Key Benefits:**

| Problem | Helm Solution |
|---------|--------------|
| **Hard to manage multiple environments** | Use values-{env}.yaml files |
| **Difficult rollbacks** | `helm rollback` to any previous version |
| **Version tracking** | Helm automatically versions releases |
| **Config duplication** | Templates with variables {{ .Values.image }} |
| **Complex dependencies** | Chart dependencies in Chart.yaml |

**Real Example - Multi-Environment:**

```yaml
# values-dev.yaml
replicaCount: 1
image:
  tag: latest
resources:
  limits:
    memory: "512Mi"

# values-prod.yaml
replicaCount: 3
image:
  tag: v1.2.3
resources:
  limits:
    memory: "2Gi"
```

**Strong Interview Answer:**
> "Helm is the package manager for Kubernetes, similar to npm for Node.js. It solves the problem of managing complex Kubernetes deployments across multiple environments. Instead of maintaining dozens of YAML files with hardcoded values, you create one Helm chart with templates and variable substitution. For example, at companies like Deutsche Bank, they have separate values files for dev, staging, and prod - same chart, different configurations. Helm also provides built-in version control and rollback capabilities. If a deployment fails, you can rollback to the previous working version with one command. Additionally, Helm charts can be stored in repositories and shared across teams, promoting standardization. The combination of templating, versioning, and easy rollbacks makes Helm essential for production Kubernetes deployments."

---

### Q21: How does containerization help microservices?

**Short Answer:**

Containers package applications with all dependencies, ensuring consistency across environments.

**Docker in Microservices Architecture:**

```
Build Once, Run Anywhere:
Developer Laptop → CI/CD → Staging → Production
  (same container image across all environments)
```

**Key Benefits:**

| Problem Without Containers | Solution With Containers |
|---------------------------|-------------------------|
| "Works on my machine" syndrome | Same environment everywhere |
| Dependency conflicts | Each container isolated |
| Slow environment setup | Pull image, run instantly |
| Resource waste | Lightweight, share OS kernel |
| Deployment complexity | Deploy = run container |

**Microservice Container Example:**

```
auth-service container:
├── Java 17 runtime
├── auth-service.jar
├── Dependencies (libraries)
└── Configuration (minimal)

Runs identically on:
- Mac (dev)
- Linux (prod)
- Windows (CI/CD)
```

**Kubernetes + Docker Integration:**

```
Kubernetes manages:
├── When to start containers (Deployments)
├── How many replicas (Auto-scaling)
├── Health checks (Liveness/Readiness)
└── Networking (Services, Ingress)

Docker provides:
└── The container image to run
```

**Strong Interview Answer:**
> "Containerization with Docker ensures that microservices run consistently across all environments. Each microservice is packaged as a Docker image with its runtime, dependencies, and application code. This eliminates 'works on my machine' problems because the same container image is used in development, staging, and production. Containers are lightweight compared to VMs - they share the host OS kernel while providing isolation. When deployed to Kubernetes, containers enable auto-scaling, rolling updates, and self-healing. For example, if a container crashes, Kubernetes automatically restarts it. This combination of portability, consistency, and operational benefits makes containers essential for microservices in production environments."

---

## Real Interview Scenarios

### Scenario 1: "Tell me about a microservices migration you've worked on"

**Weak Answer:**
> "I built microservices using Spring Boot and deployed them."

**Strong Answer:**
> "I refactored a monolithic URL shortener into 3 microservices - Auth, URL, and Analytics - using the strangler fig pattern. Started by building the Auth service alongside the monolith, both sharing the database initially. Implemented feature flags in the API Gateway backed by Redis for gradual traffic routing. Rolled out from 10% to 100% over 4 weeks, monitoring error rates and latency in Prometheus. Used Resilience4j circuit breakers to prevent cascade failures. The database migration happened last - started with replication, then dual writes via Kafka events, finally separate PostgreSQL instances. This provided zero downtime and instant rollback capability via feature flag toggles."

---

### Scenario 2: "How do you handle failures in distributed systems?"

**Weak Answer:**
> "I use try-catch blocks and return error messages."

**Strong Answer:**
> "I implement multiple layers of resilience. At the application level, I use Resilience4j circuit breakers to prevent cascade failures - if Auth service is down, I open the circuit and return cached data or fail fast rather than overwhelming it with retries. I implement retry with exponential backoff for transient failures, and rate limiting with Bucket4j to prevent abuse. At the infrastructure level, I use health checks with Kubernetes liveness and readiness probes to automatically restart unhealthy pods. For gradual deployments, I use canary releases with automated rollback based on error rate metrics in Prometheus. Feature flags provide instant rollback for critical failures. This defense-in-depth approach ensures the system degrades gracefully rather than complete failure."

---

### Scenario 3: "When would you NOT use microservices?"

**Strong Answer:**
> "Microservices add significant complexity - distributed tracing, network latency, data consistency challenges. I wouldn't use them for:
>
> 1. **Small teams** (<10 engineers) - coordination overhead exceeds benefits
> 2. **Unclear domain boundaries** - premature splitting leads to tight coupling
> 3. **Low traffic applications** - monolith is simpler and adequate
> 4. **Tight latency requirements** - network calls add 5-20ms overhead
> 5. **Strong consistency needs** - distributed transactions are complex
>
> Martin Fowler's advice: 'Start with a monolith, extract microservices when you feel pain.' The pain signals are: deployments block each other, teams stepping on each other's code, different scaling needs per module. Microservices are a tool for organizational scaling, not a goal in themselves."

---

## Reactive Programming

### Q22: What is Reactive Programming and when should you use it?

**Short Answer:**

**Reactive Programming** = Non-blocking, event-driven programming model that uses callbacks and event loops to handle I/O operations without blocking threads.

**Key Concept:**

Traditional (Blocking):
- Thread waits while database/API call completes
- 1000 requests = 1000+ threads needed
- High memory usage, thread context-switching overhead

Reactive (Non-blocking):
- Thread registers callback and moves on
- Event loop notifies when operation completes
- 1000 requests = 10-50 threads (event loops)
- Low memory, high throughput

**Reactive Types in Spring:**

| Type | Represents | Example |
|------|-----------|---------|
| **Mono<T>** | 0 or 1 item | `Mono<User>` - single user or empty |
| **Flux<T>** | 0 to N items | `Flux<Order>` - stream of orders |

**When to Use Reactive:**

| Scenario | Blocking | Reactive |
|----------|---------|----------|
| **High concurrency** | 10K users = 10K threads | 10K users = 50 threads ✅ |
| **I/O heavy** | Threads wait on DB/API | Threads never block ✅ |
| **Low latency** | Thread blocking adds delay | Async operations ✅ |
| **Simple CRUD** | Spring MVC is simpler ✅ | Unnecessary complexity |
| **CPU-intensive** | Better with blocking ✅ | No benefit |

**Example: Blocking vs Reactive**

**Blocking (Spring MVC):**
```java
@GetMapping("/user/{id}")
public User getUser(@PathVariable Long id) {
    // Thread BLOCKS here for 100ms
    User user = userRepository.findById(id);

    // Thread BLOCKS here for 200ms
    List<Order> orders = orderService.getOrders(user);

    // Total: 300ms with thread blocked entire time
    return user;
}
```

**Reactive (Spring WebFlux):**
```java
@GetMapping("/user/{id}")
public Mono<User> getUser(@PathVariable Long id) {
    return userRepository.findById(id)  // Returns immediately
        .flatMap(user ->                // Callback when user arrives
            orderService.getOrders(user) // Returns immediately
                .map(orders -> {         // Callback when orders arrive
                    user.setOrders(orders);
                    return user;
                })
        );
    // Thread is FREE entire 300ms to handle other requests
}
```

**Strong Interview Answer:**
> "Reactive programming is a non-blocking, event-driven model that uses callbacks and event loops instead of blocking threads for I/O operations. In Spring, we use Mono for single results and Flux for streams. The key benefit is efficiency - a blocking system needs thousands of threads for thousands of concurrent requests because each thread waits for I/O. Reactive systems use 10-50 event loop threads that never block - they register callbacks and move on to handle other requests. When I/O completes, the event loop triggers the callback. This is why Spring Cloud Gateway uses reactive - it needs to handle high concurrency without thread overhead. However, I wouldn't use reactive for simple CRUD apps where Spring MVC is simpler and adequate. Companies like Netflix, LinkedIn, and PayPal use reactive for high-traffic APIs where thread efficiency is critical."

---

### Q23: What is the difference between Reactive Programming and CompletableFuture?

**Short Answer:**

Both handle async operations, but **reactive uses event loops** while **CompletableFuture uses thread pools**.

**Key Difference:**

| Aspect | CompletableFuture | Reactive (Mono/Flux) |
|--------|------------------|---------------------|
| **Thread model** | Thread pool (blocking underneath) | Event loop (non-blocking) |
| **Threads needed** | 1 thread per async operation | Few event loop threads |
| **1000 parallel calls** | 1000+ threads | 10-50 threads |
| **Blocking** | Threads block on `.get()` | Never blocks |
| **Backpressure** | ❌ No built-in support | ✅ Yes (Flow control) |
| **Memory** | High (many threads) | Low (few threads) |
| **Use case** | Parallel independent tasks | High-concurrency I/O |

**Example Comparison:**

**CompletableFuture:**
```java
CompletableFuture<User> userFuture =
    CompletableFuture.supplyAsync(() -> userService.getUser(id));

CompletableFuture<Orders> ordersFuture =
    CompletableFuture.supplyAsync(() -> orderService.getOrders(id));

// Still uses worker threads that block on I/O
// 1000 requests = ~3000 threads (user + orders + analytics per request)
```

**Reactive:**
```java
Mono<User> userMono = userService.getUser(id);  // Returns immediately
Mono<Orders> ordersMono = orderService.getOrders(id);  // Returns immediately

Mono.zip(userMono, ordersMono)
    .map(tuple -> combine(tuple.T1, tuple.T2));

// Event loop threads never block
// 1000 requests = 10 event loop threads
```

**Timeline Comparison:**

**CompletableFuture (3 parallel API calls):**
```
Main thread: Submit 3 tasks to thread pool
├─ Worker Thread 1: [BLOCKS 200ms on API A]
├─ Worker Thread 2: [BLOCKS 300ms on API B]
└─ Worker Thread 3: [BLOCKS 150ms on API C]
Main thread: Wait and collect results
Total: 300ms, 3 threads BLOCKED entire time
```

**Reactive (3 parallel API calls):**
```
Event Loop Thread: Register callback for API A → FREE immediately
Event Loop Thread: Register callback for API B → FREE immediately
Event Loop Thread: Register callback for API C → FREE immediately
[All 3 operations running in parallel, thread handling OTHER requests]
Event Loop: API C done (150ms) → trigger callback
Event Loop: API A done (200ms) → trigger callback
Event Loop: API B done (300ms) → trigger callback → combine results
Total: 300ms, thread was FREE entire time
```

**Strong Interview Answer:**
> "CompletableFuture provides async execution but still uses thread pools underneath - each async operation consumes a thread that blocks on I/O. For 1000 parallel requests, you might need 3000 threads. Reactive programming with Mono/Flux uses event loops instead - threads register callbacks and immediately move on without blocking. The event loop notifies when operations complete. This means 1000 requests might only need 10-50 event loop threads. CompletableFuture is fine for parallelizing a few independent tasks, but reactive is essential for high-concurrency systems like API gateways where thread efficiency is critical. Reactive also provides backpressure for flow control, which CompletableFuture doesn't have. This is why Spring Cloud Gateway uses reactive - it can handle millions of requests without creating millions of threads."

---

### Q24: How does reactive programming handle dependent API calls?

**Short Answer:**

Reactive handles **both independent and dependent** calls efficiently using `.flatMap()` for chaining.

**Common Misconception:**
❌ "Reactive only works when API calls are independent (parallel)"

**Reality:**
✅ Reactive works for BOTH independent (parallel) and dependent (sequential) calls
✅ The key benefit is thread never blocks, even for sequential operations

**Independent Calls (Parallel):**
```java
Mono<User> userMono = userService.getUser(id);
Mono<Profile> profileMono = profileService.getProfile(id);
Mono<Orders> ordersMono = orderService.getOrders(id);

// Execute all 3 in parallel
Mono.zip(userMono, profileMono, ordersMono)
    .map(tuple -> combine(tuple));

// Timeline: All 3 start immediately, complete in parallel
// Thread: FREE entire time
```

**Dependent Calls (Sequential):**
```java
userService.getUser(id)          // Step 1: Get user
    .flatMap(user ->              // Step 2: Use user to get orders
        orderService.getOrders(user.getId())
            .flatMap(orders ->    // Step 3: Use orders to calculate total
                paymentService.calculateTotal(orders)
                    .map(total -> {
                        user.setTotal(total);
                        return user;
                    })
            )
    );

// Timeline: Sequential execution (200ms + 300ms + 100ms = 600ms)
// Thread: Still FREE - just registers callbacks at each step
```

**Why Thread is Free (Event Loop + Callbacks):**

**Step-by-step timeline:**
```
T=0ms:   Thread calls getUser() → registers callback → moves on to handle Request #2
T=200ms: Event loop detects getUser() done → triggers callback
         Thread executes callback: calls getOrders() → registers callback → moves on
T=500ms: Event loop detects getOrders() done → triggers callback
         Thread executes callback: calls calculateTotal() → registers callback → moves on
T=600ms: Event loop detects calculateTotal() done → triggers final callback
         Thread executes callback: combines results → sends response
```

**Key Insight:**
- Sequential execution time is SAME (600ms blocking vs 600ms reactive)
- BUT in reactive, thread handles hundreds of other requests during those 600ms
- In blocking, thread sits idle waiting for I/O

**Blocking vs Reactive Comparison:**

**Blocking (Spring MVC):**
```java
User user = userService.getUser(id);           // Thread BLOCKS 200ms
Orders orders = orderService.getOrders(user);   // Thread BLOCKS 300ms
Total total = paymentService.calculateTotal(orders); // Thread BLOCKS 100ms

// Timeline: 600ms with thread BLOCKED entire time
// 10 concurrent requests = 10 threads needed
```

**Reactive (Spring WebFlux):**
```java
return userService.getUser(id)
    .flatMap(user -> orderService.getOrders(user))
    .flatMap(orders -> paymentService.calculateTotal(orders));

// Timeline: 600ms with thread FREE entire time (handling other requests)
// 10 concurrent requests = 1-2 threads needed
```

**Restaurant Analogy:**

**Blocking Waiter:**
- Take order from Table 1
- Walk to kitchen and WAIT until food ready (5 minutes of standing)
- Deliver food to Table 1
- Now take order from Table 2
Result: 1 waiter = 12 tables per hour

**Reactive Waiter:**
- Take order from Table 1 → give to kitchen → immediately take order from Table 2
- Kitchen rings bell → deliver to Table 1 → take order from Table 3
- Kitchen rings bell → deliver to Table 2 → take order from Table 4
Result: 1 waiter = 50 tables per hour (same quality, more efficient)

**Strong Interview Answer:**
> "Reactive programming works efficiently for both independent and dependent API calls. For independent calls, I use Mono.zip() to execute them in parallel. For dependent calls where output of one is input to another, I use .flatMap() to chain them sequentially. The critical difference from blocking code is that in reactive, the thread never blocks even during sequential operations - it registers a callback and immediately moves on to handle other requests. When each operation completes, the event loop triggers the next callback. For example, in a KYC verification flow with 3 dependent checks taking 600ms total, the thread is free to handle hundreds of other requests during that time, whereas in blocking code the thread sits idle waiting. This is the power of reactive - not faster execution time, but massively better thread utilization and throughput."

---

### Q25: What companies use reactive programming?

**Short Answer:**

**Major Tech Companies:**
- **Netflix**: Spring WebFlux for API Gateway (Zuul)
- **LinkedIn**: Play Framework (reactive)
- **PayPal**: Akka for payment processing
- **Twitter**: Finagle (reactive RPC framework)
- **Walmart**: Reactive microservices for e-commerce
- **Alibaba**: RxJava for high-traffic systems
- **Microsoft**: Reactive Extensions (Rx)

**Industries Using Reactive:**
- **Fintech**: High-frequency trading, payment gateways
- **E-commerce**: Black Friday traffic spikes
- **Streaming**: Real-time video/audio streaming
- **Gaming**: Multiplayer game servers
- **IoT**: Sensor data processing

**Framework Adoption:**

| Framework | Used By |
|-----------|---------|
| **Spring WebFlux** | Netflix, Alibaba, Walmart |
| **Akka** | PayPal, Lightbend customers |
| **Play Framework** | LinkedIn, Coursera |
| **Vert.x** | Red Hat, Eclipse Foundation |
| **RxJava** | Netflix, Alibaba, Uber |

**Strong Interview Answer:**
> "Reactive programming is widely used in companies with high-concurrency requirements. Netflix uses Spring WebFlux for their API Gateway to handle millions of requests with minimal threads. LinkedIn built their platform on Play Framework which is reactive. PayPal uses Akka for payment processing where thread efficiency and fault tolerance are critical. Twitter created Finagle, their own reactive RPC framework. It's particularly common in fintech for payment gateways, e-commerce for handling traffic spikes, and streaming platforms where real-time data processing is essential. Spring WebFlux has become the industry standard for reactive in the Java ecosystem."

---

### Q26: What is Spring WebFlux and how is it different from Spring MVC?

**Short Answer:**

**Spring WebFlux** = Spring's reactive web framework (non-blocking)
**Spring MVC** = Spring's traditional web framework (blocking)

**Key Differences:**

| Aspect | Spring MVC | Spring WebFlux |
|--------|-----------|---------------|
| **Threading Model** | One thread per request | Event loop threads |
| **I/O** | Blocking | Non-blocking |
| **Return Types** | `User`, `List<User>` | `Mono<User>`, `Flux<User>` |
| **Server** | Tomcat (servlet container) | Netty (event-driven) |
| **Annotations** | `@RestController`, `@GetMapping` | Same! |
| **Best For** | Standard CRUD apps | High-concurrency systems |
| **Database** | JDBC (blocking) | R2DBC (reactive) |
| **Thread Pool** | 200 threads (default) | 10-50 event loop threads |
| **10K concurrent** | 10K threads needed | 50 threads enough |

**Code Comparison:**

**Spring MVC:**
```java
@RestController
public class UserController {

    @GetMapping("/users/{id}")
    public User getUser(@PathVariable Long id) {
        return userRepository.findById(id);  // Blocks thread
    }
}

// Uses: Tomcat with blocking I/O
// Database: Spring Data JPA (JDBC - blocking)
```

**Spring WebFlux:**
```java
@RestController
public class UserController {

    @GetMapping("/users/{id}")
    public Mono<User> getUser(@PathVariable Long id) {
        return userRepository.findById(id);  // Non-blocking
    }
}

// Uses: Netty with event loop
// Database: Spring Data R2DBC (reactive)
```

**When to Use Spring WebFlux:**

| Use Case | Why WebFlux |
|----------|------------|
| **API Gateway** | Handle thousands of concurrent requests ✅ |
| **Real-time streaming** | Push updates to clients (SSE, WebSocket) ✅ |
| **High-traffic APIs** | Thread efficiency critical ✅ |
| **Microservices mesh** | Service-to-service calls non-blocking ✅ |

**When to Use Spring MVC:**

| Use Case | Why MVC |
|----------|---------|
| **Simple CRUD** | Easier to understand, less complexity ✅ |
| **Blocking dependencies** | JDBC, legacy libraries ✅ |
| **Team familiarity** | Most developers know MVC ✅ |
| **Low traffic** | Thread overhead not a problem ✅ |

**Can Services Mix?**

✅ **YES!** Not all services need to be reactive:
- API Gateway: Spring WebFlux (high concurrency)
- Auth Service: Spring MVC (simple CRUD)
- URL Service: Spring MVC (database-heavy)
- Analytics Service: Spring MVC (batch processing)

**Strong Interview Answer:**
> "Spring WebFlux is Spring's reactive web framework built on Project Reactor and Netty, while Spring MVC is the traditional blocking framework on Tomcat. The key difference is threading: MVC uses one thread per request that blocks on I/O, while WebFlux uses a small number of event loop threads that never block. WebFlux returns Mono and Flux instead of direct objects, and requires reactive databases like R2DBC instead of JDBC. However, the annotations like @RestController and @GetMapping are the same, making it familiar. I'd use WebFlux for API Gateways and high-concurrency systems where thread efficiency is critical, but stick with Spring MVC for standard CRUD applications where simplicity matters more than throughput. Companies like Netflix use WebFlux for their gateway to handle millions of requests, but many of their backend services still use Spring MVC."

---

### Q27: Why use reactive programming specifically in API Gateway?

**Short Answer:**

API Gateway is the **perfect use case** for reactive programming because it handles **high concurrency** with **I/O-heavy operations**.

**Why API Gateway Needs Reactive:**

| Characteristic | Why Reactive Fits |
|----------------|------------------|
| **High concurrent requests** | 10,000 simultaneous users → 50 reactive threads vs 10,000 blocking threads |
| **I/O heavy workload** | Gateway mostly waits for backend responses, doesn't do heavy processing |
| **Routing & forwarding** | Just validates JWT and forwards → perfect for non-blocking |
| **Entry point bottleneck** | ALL external traffic flows through gateway → must be extremely efficient |

**What API Gateway Does:**

```
1. Receive request from client
2. Validate JWT token (fast, in-memory operation)
3. Forward request to backend service (I/O - WAIT for response)
4. Return response to client

Step 3 is 90% of the time spent - WAITING for backend
```

**Reactive Advantage:**

**Blocking Gateway (Spring MVC):**
```
Request 1 → Thread 1 [validates JWT → BLOCKS waiting for backend]
Request 2 → Thread 2 [validates JWT → BLOCKS waiting for backend]
Request 3 → Thread 3 [validates JWT → BLOCKS waiting for backend]
...
Request 10,000 → Thread 10,000 [validates JWT → BLOCKS]

Result: 10,000 threads, high memory usage, context-switching overhead
```

**Reactive Gateway (Spring Cloud Gateway):**
```
Request 1 → Event Loop Thread [validates JWT → registers callback → FREE]
Request 2 → Same Thread [validates JWT → registers callback → FREE]
Request 3 → Same Thread [validates JWT → registers callback → FREE]
...
Request 10,000 → Still ~50 threads total

Result: 50 threads handle 10,000 requests, low memory, no context-switching
```

**Spring Cloud Gateway Requirement:**

Spring Cloud Gateway is **built on Spring WebFlux** by design. You must use reactive patterns - it's not optional.

**Backend Services Can Stay Blocking:**

```
✅ API Gateway: Spring Cloud Gateway (reactive) - high concurrency entry point
✅ Auth Service: Spring MVC (blocking) - simple CRUD, database operations
✅ URL Service: Spring MVC (blocking) - business logic, database-heavy
✅ Analytics Service: Spring MVC (blocking) - batch processing, reporting
```

**Key Insight:**

Gateway doesn't do **heavy processing** - it just:
- Routes requests
- Validates JWT
- Forwards to backend services

This is **all I/O operations** with minimal CPU work - exactly where reactive shines.

**Real-World Example:**

Netflix API Gateway (Zuul):
- Handles millions of requests per second
- Uses reactive programming (WebFlux)
- Backend services: Mix of reactive and blocking
- Result: Can handle massive traffic spikes with minimal infrastructure

**Strong Interview Answer:**
> "I used reactive programming in the API Gateway because it's the entry point for all external traffic and needs to handle thousands of concurrent requests efficiently. The gateway's workload is I/O-heavy - it validates JWT tokens and forwards requests to backend services, spending most time waiting for responses. With reactive programming, 10,000 concurrent requests need only 50 event loop threads instead of 10,000 blocking threads. Additionally, Spring Cloud Gateway is built on Spring WebFlux, so reactive is required. However, I kept the backend services like Auth-Service and URL-Service as blocking Spring MVC because they do actual business logic and database operations where simplicity matters more than thread efficiency. This hybrid approach is the industry standard - reactive at the gateway for high concurrency, blocking in backend services for developer productivity."

---

### Q28: What's the difference between CORS in Spring MVC vs Spring WebFlux?

**Short Answer:**

CORS configuration is **conceptually the same**, but uses **different implementation classes** for servlet vs reactive servers.

**Key Differences:**

| Aspect | Spring MVC | Spring WebFlux |
|--------|-----------|---------------|
| **Server** | Tomcat (servlet-based) | Netty (reactive) |
| **Filter Class** | `CorsFilter` | `CorsWebFilter` |
| **Package** | `org.springframework.web.cors` | `org.springframework.web.cors.reactive` |
| **Filter Type** | Servlet filter (blocking) | WebFilter (non-blocking) |
| **Config Source** | `UrlBasedCorsConfigurationSource` | `UrlBasedCorsConfigurationSource` (reactive version) |

**Code Comparison:**

**Spring MVC (Blocking):**
```java
@Configuration
public class CorsConfig {

    @Bean
    public CorsFilter corsFilter() {
        CorsConfiguration config = new CorsConfiguration();
        config.setAllowedOrigins(Arrays.asList("http://localhost:4200"));
        config.setAllowedMethods(Arrays.asList("GET", "POST", "PUT", "DELETE"));
        config.setAllowedHeaders(Arrays.asList("*"));
        config.setAllowCredentials(true);

        UrlBasedCorsConfigurationSource source =
            new UrlBasedCorsConfigurationSource();
        source.registerCorsConfiguration("/**", config);

        return new CorsFilter(source);  // Servlet-based filter
    }
}
```

**Spring WebFlux (Reactive):**
```java
@Configuration
public class CorsConfig {

    @Bean
    public CorsWebFilter corsWebFilter() {
        CorsConfiguration config = new CorsConfiguration();
        config.setAllowedOrigins(Arrays.asList("http://localhost:4200"));
        config.setAllowedMethods(Arrays.asList("GET", "POST", "PUT", "DELETE"));
        config.setAllowedHeaders(Arrays.asList("*"));
        config.setAllowCredentials(true);

        org.springframework.web.cors.reactive.UrlBasedCorsConfigurationSource source =
            new org.springframework.web.cors.reactive.UrlBasedCorsConfigurationSource();
        source.registerCorsConfiguration("/**", config);

        return new CorsWebFilter(source);  // Reactive web filter
    }
}
```

**What's the Same:**

Both use identical `CorsConfiguration` with same methods:
- `setAllowedOrigins()` - Which domains can access
- `setAllowedMethods()` - Which HTTP methods allowed
- `setAllowedHeaders()` - Which headers allowed
- `setAllowCredentials()` - Allow cookies/auth headers
- `setMaxAge()` - Preflight cache duration

**What's Different:**

**Spring MVC:**
```
Request → Servlet Filter Chain → CorsFilter (blocks thread) → Controller
```

**Spring WebFlux:**
```
Request → Reactive Filter Chain → CorsWebFilter (non-blocking) → Controller
```

**Alternative: Annotation-Based (Works for Both):**

```java
@RestController
@CrossOrigin(origins = "http://localhost:4200")
public class UserController {

    // Spring MVC version
    @GetMapping("/users")
    public List<User> getUsers() {
        return userService.getAllUsers();
    }

    // Spring WebFlux version
    @GetMapping("/users")
    public Mono<List<User>> getUsers() {
        return userService.getAllUsers();
    }
}
```

**Why Two Different Classes?**

- **MVC**: Uses servlet filter chain that operates on blocking threads
- **WebFlux**: Uses reactive filter chain that operates on event loop threads
- Cannot mix servlet filters with reactive web filters - different execution models

**Common Interview Question:**

"Can I use `CorsFilter` in Spring Cloud Gateway?"

**Answer:** No, you must use `CorsWebFilter` because Spring Cloud Gateway is built on WebFlux/Netty, not servlet containers.

**Strong Interview Answer:**
> "CORS configuration is conceptually identical between Spring MVC and WebFlux - same allowed origins, methods, and headers using CorsConfiguration. The difference is the implementation class: MVC uses CorsFilter which is a servlet filter that blocks threads, while WebFlux uses CorsWebFilter from the reactive package which is non-blocking. In my API Gateway using Spring Cloud Gateway, I use CorsWebFilter because it's built on WebFlux and Netty. The actual CORS logic - validating origins, adding headers - is the same, but the filter execution model differs to match the blocking vs reactive threading model."

---

### Q29: How do you ensure correct filter execution order in Spring Cloud Gateway?

**Short Answer:**

Use `@Order` annotation with **lower numbers executing first**. CORS must run before authentication to allow preflight requests.

**Why Filter Order Matters:**

```
❌ Wrong Order:
Request → Authentication Filter → CORS Filter → Backend
Problem: OPTIONS preflight has no JWT token → Auth fails → CORS never runs

✅ Correct Order:
Request → CORS Filter → Authentication Filter → Backend
Result: OPTIONS preflight gets CORS headers → Auth skipped for OPTIONS → Success
```

**How to Control Order:**

**Method 1: Using `@Order` Annotation**
```java
@Configuration
public class CorsConfig {

    @Bean
    @Order(-100)  // High priority - executes first
    public CorsWebFilter corsWebFilter() {
        // CORS configuration
    }
}
```

**Method 2: Implementing `Ordered` Interface**
```java
@Component
public class CorsFilter implements GlobalFilter, Ordered {

    @Override
    public Mono<Void> filter(ServerWebExchange exchange, GatewayFilterChain chain) {
        // Filter logic
    }

    @Override
    public int getOrder() {
        return -100;  // High priority
    }
}
```

**Method 3: Order in Route Configuration**
```java
@Bean
public RouteLocator customRouteLocator(RouteLocatorBuilder builder) {
    return builder.routes()
        .route("url-service", r -> r
            .path("/api/urls/**")
            .filters(f -> f
                .filter(loggingFilter)      // Executes first
                .filter(authFilter)         // Then this
                .filter(rateLimitFilter)    // Finally this
            )
            .uri("lb://URL-SERVICE"))
        .build();
}
```

**Recommended Filter Order:**

| Order Value | Filter | Purpose |
|-------------|--------|---------|
| **-100** | CORS Filter | Handle preflight, add CORS headers |
| **0** | Logging Filter | Log incoming requests |
| **1** | Authentication Filter | Validate JWT tokens |
| **2** | Rate Limiting Filter | Check request rate limits |
| **3** | Authorization Filter | Verify permissions |

**Complete Request Flow:**

```
1. Request arrives
   ↓
2. CORS Filter (Order = -100)
   - Add Access-Control-* headers
   - For OPTIONS: return 200 immediately
   ↓
3. Logging Filter (Order = 0)
   - Log request details
   ↓
4. Authentication Filter (Order = 1)
   - Validate JWT token (skipped for OPTIONS)
   ↓
5. Rate Limiting Filter (Order = 2)
   - Check if user exceeded rate limit
   ↓
6. Authorization Filter (Order = 3)
   - Check if user has permission for resource
   ↓
7. Route to backend service
   ↓
8. Response flows back through filters in reverse
```

**Common Mistake:**

```java
// ❌ BAD: No explicit order
@Bean
public CorsWebFilter corsWebFilter() {
    // Relies on default order - fragile!
}

// ✅ GOOD: Explicit order
@Bean
@Order(-100)
public CorsWebFilter corsWebFilter() {
    // Clear intent, predictable behavior
}
```

**Why CORS Must Be First:**

CORS preflight requests (OPTIONS):
- Don't include `Authorization` header
- Don't include request body
- Just check if CORS allows the actual request

If authentication runs before CORS:
```
OPTIONS /api/users
↓
Authentication Filter: No JWT token → 401 Unauthorized
↓
CORS Filter: Never reached
↓
Browser: CORS error (even though it's really an auth error)
```

**Best Practice: Use Constants**

```java
public class FilterOrder {
    public static final int CORS_FILTER = -100;
    public static final int LOGGING_FILTER = 0;
    public static final int AUTH_FILTER = 1;
    public static final int RATE_LIMIT_FILTER = 2;
}

@Bean
@Order(FilterOrder.CORS_FILTER)
public CorsWebFilter corsWebFilter() {
    // Implementation
}
```

**Global vs Route-Specific Filters:**

**Global Filters** (apply to all routes):
```java
@Component
@Order(-100)
public class GlobalCorsFilter implements GlobalFilter {
    @Override
    public Mono<Void> filter(ServerWebExchange exchange, GatewayFilterChain chain) {
        // Runs for ALL routes
        return chain.filter(exchange);
    }
}
```

**Route-Specific Filters** (apply to specific routes):
```java
.route("auth-service", r -> r
    .path("/api/auth/**")
    .filters(f -> f.filter(someFilter))  // Only for this route
    .uri("lb://AUTH-SERVICE"))
```

**My Implementation:**

```java
@Configuration
public class CorsConfig {

    @Bean
    @Order(-100)  // Explicit high priority
    public CorsWebFilter corsWebFilter() {
        CorsConfiguration config = new CorsConfiguration();
        config.setAllowedOrigins(Arrays.asList("http://localhost:4200"));
        config.setAllowedMethods(Arrays.asList("GET", "POST", "PUT", "DELETE", "OPTIONS"));

        UrlBasedCorsConfigurationSource source = new UrlBasedCorsConfigurationSource();
        source.registerCorsConfiguration("/**", config);

        return new CorsWebFilter(source);
    }
}
```

**Strong Interview Answer:**
> "I control filter order using `@Order` annotation where lower numbers execute first. The most critical order is ensuring CORS filter runs before authentication. I use `@Order(-100)` on CorsWebFilter because CORS preflight OPTIONS requests don't contain JWT tokens - if authentication ran first, all preflight requests would fail with 401 Unauthorized before CORS headers could be added. My typical order is: CORS (-100), Logging (0), Authentication (1), Rate Limiting (2), Authorization (3). For route-specific filters in GatewayConfig, they execute in the order added to the filter chain. I use constants like FilterOrder.CORS_FILTER to make ordering explicit and maintainable, rather than relying on Spring's default behavior which can change between versions."

---

## Build & Deployment

### Q30: How do you optimize JVM settings for different microservices in Docker?

**Short Answer:**

Tailor JVM flags based on service workload. Use **container-aware settings**, **appropriate GC**, and **workload-specific optimizations**.

**Common JVM Optimizations for All Services:**

```dockerfile
ENV JAVA_OPTS="-Djava.security.egd=file:/dev/./urandom \
               -XX:+UseContainerSupport \
               -XX:MaxRAMPercentage=75.0"
```

| Flag | Purpose | Why Important |
|------|---------|---------------|
| `-Djava.security.egd=file:/dev/./urandom` | Non-blocking random number generation | Faster startup (2-5 seconds improvement) |
| `-XX:+UseContainerSupport` | JVM respects container memory limits | Prevents OOM kills in Kubernetes |
| `-XX:MaxRAMPercentage=75.0` | Use 75% of container memory | Leaves 25% for OS and overhead |

**Service-Specific Optimizations:**

**1. Eureka Server (Service Discovery)**
```dockerfile
# Basic settings - Eureka is lightweight
ENV JAVA_OPTS="-Djava.security.egd=file:/dev/./urandom \
               -XX:+UseContainerSupport \
               -XX:MaxRAMPercentage=75.0"
```
**Why:** Eureka just maintains a registry in memory. No heavy computation, no GC tuning needed.

---

**2. Auth Service (JWT Token Generation)**
```dockerfile
ENV JAVA_OPTS="-Djava.security.egd=file:/dev/./urandom \
               -XX:+UseContainerSupport \
               -XX:MaxRAMPercentage=75.0 \
               -XX:+UseG1GC"
```

| Flag | Why for Auth Service |
|------|---------------------|
| `+UseG1GC` | G1 Garbage Collector handles frequent short-lived objects (JWT tokens) better than default |
| `egd=urandom` | **CRITICAL** for JWT - SecureRandom blocks on `/dev/random`, causing 30+ second delays |

**Why G1GC for Auth Service?**
- Auth service creates **many short-lived objects**: JWT tokens, password hashes, user DTOs
- G1GC is **better at handling mixed workloads** (short-lived + long-lived objects)
- Reduces pause times during token generation bursts

---

**3. URL Service (String-Heavy Workload)**
```dockerfile
ENV JAVA_OPTS="-Djava.security.egd=file:/dev/./urandom \
               -XX:+UseContainerSupport \
               -XX:MaxRAMPercentage=75.0 \
               -XX:+UseG1GC \
               -XX:+UseStringDeduplication"
```

| Flag | Why for URL Service |
|------|-------------------|
| `+UseStringDeduplication` | URLs have common patterns (`http://`, `www.`, `.com`) - deduplicate to save 20-30% memory |
| `+UseG1GC` | Required for string deduplication (only works with G1) |

**How String Deduplication Works:**
```
Without deduplication:
"http://example.com"  → 18 bytes
"http://google.com"   → 17 bytes
"http://github.com"   → 17 bytes
Total: 52 bytes

With deduplication:
"http://"      → 7 bytes (shared)
"example.com"  → 11 bytes
"google.com"   → 10 bytes
"github.com"   → 10 bytes
Total: 38 bytes (27% savings)
```

**Real Impact:** In URL shortener with 100K URLs, saves ~25-30 MB of memory.

---

**4. API Gateway (Low-Latency Reactive Workload)**
```dockerfile
ENV JAVA_OPTS="-Djava.security.egd=file:/dev/./urandom \
               -XX:+UseContainerSupport \
               -XX:MaxRAMPercentage=75.0 \
               -XX:+UseG1GC \
               -XX:MaxGCPauseMillis=200 \
               -XX:+ParallelRefProcEnabled"
```

| Flag | Why for API Gateway |
|------|-------------------|
| `MaxGCPauseMillis=200` | Target max 200ms GC pause - **critical for low-latency gateway** |
| `ParallelRefProcEnabled` | Parallel reference processing speeds up GC in reactive event loops |
| `+UseG1GC` | Low-latency garbage collection (vs default parallel GC with longer pauses) |

**Why Low GC Pause Matters for Gateway:**
```
Scenario: Gateway handling 1000 req/sec

❌ Without MaxGCPauseMillis (default ~1 second pause):
1000 requests arrive → GC pause 1 second → 1000 requests timeout → Bad!

✅ With MaxGCPauseMillis=200:
1000 requests arrive → GC pause 200ms → 200 requests delayed slightly → OK!
```

**Why ParallelRefProcEnabled for Reactive:**
- Reactive programming creates many **weak references** (Mono/Flux subscriptions)
- Parallel processing reduces GC pause time by 30-40%
- Important when event loop is processing thousands of concurrent requests

---

**5. Analytics Service (Standard Workload)**
```dockerfile
ENV JAVA_OPTS="-Djava.security.egd=file:/dev/./urandom \
               -XX:+UseContainerSupport \
               -XX:MaxRAMPercentage=75.0 \
               -XX:+UseG1GC"
```
**Why:** Standard database CRUD operations. G1GC provides good overall performance.

---

**Comparison Table:**

| Service | G1GC | String Dedup | MaxGCPauseMillis | ParallelRefProc | Why Different |
|---------|------|--------------|------------------|-----------------|---------------|
| **Eureka** | ❌ | ❌ | ❌ | ❌ | Lightweight registry, default GC fine |
| **Auth** | ✅ | ❌ | ❌ | ❌ | Many short-lived objects (JWT tokens) |
| **URL** | ✅ | ✅ | ❌ | ❌ | Many duplicate strings (URLs) |
| **Gateway** | ✅ | ❌ | ✅ 200ms | ✅ | Low-latency reactive workload |
| **Analytics** | ✅ | ❌ | ❌ | ❌ | Standard CRUD operations |

---

**Health Check Start Period Differences:**

Different services need different startup grace periods:

```dockerfile
# Eureka Server - Fastest (no external dependencies)
HEALTHCHECK --start-period=40s

# API Gateway - Fast (only needs Eureka)
HEALTHCHECK --start-period=45s

# Auth/URL/Analytics - Slower (needs DB + Eureka)
HEALTHCHECK --start-period=60s
```

**Why Different Start Periods?**

```
Eureka Server startup:
- Load application.yml → 2s
- Initialize Eureka registry → 5s
- Start HTTP server → 3s
Total: ~10s (40s grace period = 4x buffer)

Auth Service startup:
- Load application.yml → 2s
- Connect to PostgreSQL → 8s (connection pool warmup)
- Initialize Eureka client → 5s
- Load JWT keys → 3s
- Start HTTP server → 3s
Total: ~21s (60s grace period = 3x buffer)
```

---

**Interview Pro Tip:**

> "I optimize JVM settings based on service workload. For example, my URL Service uses `UseStringDeduplication` because URLs have common patterns like 'http://' and '.com', saving 20-30% memory. The API Gateway uses `MaxGCPauseMillis=200` because it's a reactive service handling thousands of concurrent requests - long GC pauses would cause timeouts. Auth Service needs `egd=/dev/urandom` because JWT generation uses SecureRandom, which can block for 30+ seconds on `/dev/random`. I always use `UseContainerSupport` to prevent OOM kills in Kubernetes."

**Common JVM Mistakes in Docker:**

```dockerfile
# ❌ BAD: JVM doesn't respect container limits
java -Xmx2G -jar app.jar
# Container has 1GB limit → OOM killed by Kubernetes

# ✅ GOOD: JVM auto-detects container limits
java -XX:+UseContainerSupport -XX:MaxRAMPercentage=75.0 -jar app.jar
# Container has 1GB → JVM uses 750MB
```

---

## Quick Interview Tips

### Do's ✅

1. **Always mention modern alternatives** when asked about legacy tech
   - "Eureka → Kubernetes DNS"
   - "Hystrix → Resilience4j"

2. **Give timeframes** to show you keep up with industry
   - "Hystrix deprecated in November 2018"
   - "Netflix migrated over 7 years using strangler fig"

3. **Reference big tech** to demonstrate industry awareness
   - Netflix, Uber, Amazon, Airbnb examples

4. **Acknowledge pragmatic approaches** while knowing the ideal
   - "Shared DB is acceptable for transitional phase, but true microservices need separate instances"

5. **Provide metrics and numbers**
   - "10x performance improvement"
   - "50% error rate threshold for rollback"
   - "P99 latency < 500ms"

6. **Explain trade-offs**, not just solutions
   - "Eureka is simpler to learn but K8s DNS is production-standard"

7. **For reactive programming questions**, emphasize strategic use over blind adoption
   - "Reactive programming provides high throughput through non-blocking I/O, but adds complexity. I use it strategically - at the API Gateway for high concurrency, but keep backend services blocking for simplicity. The key is understanding when thread efficiency matters more than developer productivity."

---

### Don'ts ❌

1. **Don't claim something is "best" without context**
   - ❌ "Microservices are best"
   - ✅ "Microservices are best when you need independent scaling and teams"

2. **Don't memorize buzzwords without understanding**
   - Know WHY strangler fig works, not just that it exists

3. **Don't ignore your company's tech stack**
   - Use it as learning experience: "We use X, but I know Y is modern alternative"

4. **Don't oversimplify production complexity**
   - Acknowledge challenges: "Zero-downtime migration takes months, not days"

5. **Don't fake knowledge**
   - "I haven't used Istio in production, but I understand it provides service mesh capabilities"

---

## Interview Question Categories

### Architecture & Design (25%)
- Monolith to microservices migration
- Service boundaries
- Database strategies
- Communication patterns (sync vs async)

### Reactive Programming (15%)
- What is reactive programming and when to use it
- Spring WebFlux vs Spring MVC
- Reactive vs CompletableFuture
- Handling dependent API calls with flatMap
- Mono, Flux, and event loops
- Companies using reactive (Netflix, LinkedIn, PayPal)

### API Gateway & Service Mesh (15%)
- API Gateway vs Service Mesh
- Service mesh benefits and use cases
- Integration with REST/Kafka
- Developer responsibilities with service mesh

### Resilience & Reliability (20%)
- Circuit breakers (Resilience4j)
- Retry strategies
- Timeout handling
- Graceful degradation

### Deployment & Operations (15%)
- Feature flags
- Canary deployments
- Blue-green deployments
- Rollback strategies
- Kubernetes and Helm deployment
- Container orchestration

### Build & Deployment (5%)
- Executable vs library JARs
- Maven multi-module projects
- Spring Boot plugin configuration
- Artifact packaging

### Kubernetes & Helm (5%)
- Container orchestration with Kubernetes
- Helm charts for deployment
- Docker containerization benefits
- Enterprise deployment strategies

### Observability & Monitoring (5%)
- Metrics (Prometheus, Grafana)
- Logging (ELK)
- Distributed tracing (Zipkin)
- APM (New Relic, Datadog)

---

## Shared Library Architecture

### Q27: What should a shared library contain in microservices architecture?

**Short Answer:**

A shared library should be **lightweight and framework-agnostic**. It should contain only truly shared code that doesn't force framework choices on consuming services.

**What SHOULD be in a shared library:**

| Category | Examples | Why |
|----------|----------|-----|
| **DTOs** | `ErrorResponse`, `PagedResponse` | Plain data classes, no framework deps |
| **Custom Exceptions** | `UrlNotFoundException`, `UnauthorizedAccessException` | Plain Java classes |
| **Utility Classes** | `DateUtils`, `StringUtils` | No framework dependencies |
| **Constants/Enums** | `ErrorCodes`, `StatusCodes` | Plain Java |
| **Validation Annotations** | Custom validators | Only needs jakarta.validation API |

**What should NOT be in a shared library:**

| Category | Examples | Why NOT |
|----------|----------|---------|
| **Controllers** | `@RestController`, `@RestControllerAdvice` | Forces Spring Web on all services |
| **Security Configs** | `@EnableWebSecurity`, `SecurityFilterChain` | Forces Spring Security on all services |
| **JPA Entities** | `@Entity`, `@Repository` | Forces Spring Data JPA on all services |
| **Framework Configs** | `@Configuration` beans | Tight coupling to specific framework |

**Strong Interview Answer:**
> "A shared library should follow the principle of minimal dependency. It should contain only DTOs, custom exceptions, utility classes, and constants - things that are truly shared and don't force framework choices. I learned this the hard way when our shared library included `@RestControllerAdvice` for exception handling, which forced every service to include Spring Web and Spring Security. This caused issues when we added an API Gateway using WebFlux - it couldn't use the same exception handler because WebFlux requires reactive security. The fix was moving exception handlers to each service and keeping only framework-agnostic code in the shared library. This follows the microservices principle of loose coupling - each service should be free to choose its own frameworks."

---

### Q28: Why shouldn't a shared library contain Spring Security dependencies?

**Short Answer:**

Including Spring Security in a shared library creates **tight coupling** and **framework incompatibility** issues.

**Real Problem We Encountered:**

```
shared-library (contained spring-boot-starter-security)
    ├── auth-service ✅ (needs servlet security)
    ├── url-service ✅ (needs servlet security)
    ├── analytics-service ✅ (needs servlet security)
    └── api-gateway ❌ FAILED (needs REACTIVE security)
```

**The Conflict:**

| Component | Required Security | Conflict |
|-----------|------------------|----------|
| Spring MVC Services | `@EnableWebSecurity` (Servlet) | None |
| Spring Cloud Gateway | `@EnableWebFluxSecurity` (Reactive) | **Incompatible!** |

**Error Encountered:**
```
Spring MVC found on classpath, which is incompatible with Spring Cloud Gateway
```

**Why This Happens:**

1. Spring Cloud Gateway uses **WebFlux** (non-blocking, reactive)
2. `spring-boot-starter-security` auto-configures **servlet-based** security
3. Spring Boot detects both servlet and reactive → **conflict**

**The Fix:**

```
shared-library (NO framework dependencies)
    ├── auth-service (adds spring-boot-starter-security itself)
    ├── url-service (adds spring-boot-starter-security itself)
    ├── analytics-service (adds spring-boot-starter-security itself)
    └── api-gateway (adds spring-boot-starter-security → auto-detects WebFlux)
```

**Strong Interview Answer:**
> "Including Spring Security in a shared library is an anti-pattern because different services may require different security implementations. We encountered this when our shared library included spring-boot-starter-security, which worked for our servlet-based services but broke our API Gateway. Spring Cloud Gateway requires WebFlux and reactive security, but the shared library's security dependency triggered servlet-based auto-configuration, causing a conflict. The solution was removing security from the shared library and letting each service declare its own security dependency. Spring Boot then auto-detects whether to use servlet or reactive security based on other dependencies. This follows the microservices principle - services should be independently deployable with their own technology choices."

---

### Q29: How do you handle exception handling across microservices without putting it in a shared library?

**Short Answer:**

**Share the DTOs and exception classes, not the handlers.** Each service implements its own `@RestControllerAdvice` or reactive error handler.

**Architecture:**

```
shared-library/
├── dto/
│   └── ErrorResponse.java        ✅ (plain Lombok DTO)
└── exception/
    ├── UrlNotFoundException.java      ✅ (plain Java)
    ├── UrlExpiredException.java       ✅ (plain Java)
    └── UnauthorizedAccessException.java ✅ (plain Java)

url-service/
└── exception/
    └── GlobalExceptionHandler.java    ✅ (service-specific, uses shared exceptions)

auth-service/
└── exception/
    └── GlobalExceptionHandler.java    ✅ (handles auth-specific exceptions)

api-gateway/
└── config/
    └── GlobalErrorWebExceptionHandler.java ✅ (REACTIVE exception handler)
```

**Why Different Handlers Per Service:**

| Service | Exception Types | Handler Type |
|---------|----------------|--------------|
| **url-service** | `UrlNotFoundException`, `UrlExpiredException` | `@RestControllerAdvice` (Servlet) |
| **auth-service** | `UsernameNotFoundException`, `BadCredentialsException` | `@RestControllerAdvice` (Servlet) |
| **api-gateway** | Gateway-specific errors, routing failures | `WebExceptionHandler` (Reactive) |

**Code Example - Shared Exception:**
```java
// shared-library: Plain Java class, no Spring deps
public class UrlNotFoundException extends RuntimeException {
    public UrlNotFoundException(String shortUrl) {
        super("URL not found: " + shortUrl);
    }
}
```

**Code Example - Service-Specific Handler:**
```java
// url-service: Uses Spring Web
@RestControllerAdvice
public class GlobalExceptionHandler {

    @ExceptionHandler(UrlNotFoundException.class)
    public ResponseEntity<ErrorResponse> handleUrlNotFound(UrlNotFoundException ex) {
        return ResponseEntity.status(HttpStatus.NOT_FOUND)
            .body(ErrorResponse.builder()
                .status(404)
                .message(ex.getMessage())
                .build());
    }
}
```

**Strong Interview Answer:**
> "The key insight is separating what to share from how to handle it. The shared library contains the exception classes and the ErrorResponse DTO - these are plain Java with no framework dependencies. Each service then implements its own exception handler using the appropriate framework. For servlet-based services, that's `@RestControllerAdvice`. For reactive services like API Gateway, it's `WebExceptionHandler`. This approach ensures consistent error response format across services while allowing each service to choose its own framework. It also means services can handle different exceptions - auth-service handles `UsernameNotFoundException`, url-service handles `UrlNotFoundException`, but both return the same `ErrorResponse` structure for client consistency."

---

### Q30: What issues can occur when running microservices in Docker that don't appear in local development?

**Short Answer:**

Docker introduces **network isolation**, **different DNS resolution**, and **startup timing** issues that don't exist when running services locally.

**Common Issues We Encountered:**

| Issue | Local Development | Docker | Solution |
|-------|------------------|--------|----------|
| **Service URLs** | `localhost:8761` works | Container can't reach `localhost` | Use Docker service names: `eureka-server:8761` |
| **Health Checks** | curl available | Some images lack curl | Use `wget` or install curl in Dockerfile |
| **Startup Order** | Start services manually | Race conditions | Use `depends_on` with `condition: service_healthy` |
| **Network Discovery** | All on same host | Isolated networks | Define Docker network, use service names |
| **Database Connections** | Connect to `localhost:5432` | Container isolation | Use `postgres:5432` (service name) |

**Example Fix - Eureka URL:**

```yaml
# application.yml - Works locally AND in Docker
eureka:
  client:
    service-url:
      defaultZone: ${EUREKA_SERVER_URL:http://localhost:8761/eureka/}

# docker-compose.yml - Override for Docker
services:
  url-service:
    environment:
      - EUREKA_SERVER_URL=http://eureka-server:8761/eureka/
```

**Example Fix - Health Checks:**

```yaml
# docker-compose.yml
services:
  auth-service:
    healthcheck:
      test: ["CMD", "curl", "-f", "http://localhost:8081/actuator/health"]
      interval: 30s
      timeout: 10s
      retries: 5
      start_period: 60s  # Give Spring time to start
```

**Strong Interview Answer:**
> "Docker introduces several networking challenges that don't appear locally. First, containers can't use `localhost` to reach other services - you must use Docker service names as hostnames. We solved this with environment variables: `${EUREKA_SERVER_URL:http://localhost:8761/eureka/}` defaults to localhost for development but gets overridden in docker-compose. Second, health checks are critical for proper startup ordering - we use `depends_on` with `condition: service_healthy` to ensure services start only after dependencies are ready. Third, Spring Security can block health endpoints, returning 403 instead of health status. We had to add `.requestMatchers(\"/actuator/**\").permitAll()` to allow Docker health checks. Finally, Spring Cloud Gateway required special handling - we had to set `spring.main.web-application-type: reactive` to prevent Spring MVC auto-configuration conflicts."

---

### Q31: How do you pass user context between services in a microservices architecture?

**Short Answer:**

There are three common approaches: **JWT propagation**, **header forwarding**, and **context injection**.

**Our Approach - Header Forwarding:**

```
Client → API Gateway → URL Service
   │         │              │
   │  JWT    │  X-User-Name │
   └─────────┴──────────────┘
```

**Implementation:**

**1. API Gateway extracts username from JWT:**
```java
@Component
public class AuthenticationFilter extends AbstractGatewayFilterFactory<Config> {

    @Override
    public GatewayFilter apply(Config config) {
        return (exchange, chain) -> {
            String token = extractToken(exchange.getRequest());
            String username = jwtUtil.extractUsername(token);

            // Add username to header for downstream services
            ServerHttpRequest modifiedRequest = exchange.getRequest().mutate()
                .header("X-User-Name", username)
                .build();

            return chain.filter(exchange.mutate().request(modifiedRequest).build());
        };
    }
}
```

**2. Downstream service reads header:**
```java
@RestController
public class UrlController {

    @PostMapping("/api/v1/urls")
    public ResponseEntity<UrlResponse> createUrl(
            @RequestBody UrlRequest request,
            @RequestHeader("X-User-Name") String username) {  // From gateway
        return ResponseEntity.ok(urlService.createShortUrl(request, username));
    }
}
```

**Comparison of Approaches:**

| Approach | Pros | Cons |
|----------|------|------|
| **JWT Propagation** | Full claims available, self-verifying | Token size, multiple validations |
| **Header Forwarding** | Simple, lightweight | Trust boundary at gateway only |
| **Context Injection** | Type-safe, framework support | More complex setup |

**Strong Interview Answer:**
> "We use header forwarding where the API Gateway validates the JWT once and extracts the username into an `X-User-Name` header that downstream services read. This is simpler than full JWT propagation because downstream services don't need JWT libraries or secrets. The security model trusts the API Gateway as the authentication boundary - if a request reaches a downstream service, it came through the gateway and is authenticated. The alternative is propagating the full JWT to each service, which gives access to all claims but requires each service to validate the token and know the secret. For internal service-to-service calls, we could also use a service mesh with mTLS where identity is established at the infrastructure layer. Our approach works well for a gateway-centric architecture where all external traffic enters through one point."

---

## Additional Resources

**Books:**
- *Building Microservices* by Sam Newman
- *Monolith to Microservices* by Sam Newman
- *Release It!* by Michael Nygard

**Articles:**
- Martin Fowler: "Strangler Fig Application"
- Martin Fowler: "CircuitBreaker Pattern"
- Netflix Tech Blog: "Microservices Journey"

**Practice:**
- Draw architecture diagrams during interviews
- Use real project examples from your experience
- Prepare questions about their microservices challenges

---

**Document Version:** 1.4
**Last Updated:** December 16, 2025
**Next Review:** Before each interview
**New in v1.4:** Added Shared Library Architecture section with 5 questions (Q27-Q31) covering shared library design principles, Spring Security dependency issues, exception handling patterns, Docker networking challenges, and user context propagation between services - based on real debugging experience

---

**Pro Tip:** Read this document 2-3 times, then practice explaining answers out loud. Focus on WHY, not just WHAT.
