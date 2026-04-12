# System Design from First Principles

> **Series:** "System Design from First Principles" (Physics of Software)  
> **Format:** Synthesized long-term reference from 12 lectures  
> **Philosophy:** Start from physical reality — electrons, latency, physics — and derive every architectural decision upward from there.

---

## Credits & Sources

### Course

**"System Design from First Principles"** — original YouTube series.  
📺 [Full Playlist](https://www.youtube.com/playlist?list=PLA12lriZjwUOHcm2HHO3OQznvfZOBjRzn)

The course's originality lies in its synthesis: it builds a single causal thread from hardware physics through distributed consensus, where each chapter's conclusion is the next chapter's premise. No single book or paper presents it in this order or with this framing. The narrator references Google SRE experience throughout ("At Google, we call these the four golden signals") and self-identifies as **Andre** in worked examples.

---

### Primary Influences

| Source | Author(s) | What it grounds |
|---|---|---|
| [Designing Data-Intensive Applications](https://dataintensive.net) (O'Reilly, 2017) | Martin Kleppmann | Ch. 5–12: storage engines, replication, partitioning, CAP, consensus, streams |
| ["The Tail at Scale"](https://research.google/pubs/the-tail-at-scale/) (CACM, 2013) | Jeff Dean & Luiz André Barroso | Ch. 2: tail latency amplification, hedged requests |
| [Latency Numbers Every Programmer Should Know](https://norvig.com/21-days.html#answers) | Jeff Dean (popularised via Peter Norvig) | Ch. 1: the latency table |
| [Site Reliability Engineering](https://sre.google/sre-book/table-of-contents/) (O'Reilly, 2016) | Beyer, Jones, Petoff, Murphy (Google) | Ch. 2: Four Golden Signals |
| ["In Search of an Understandable Consensus Algorithm"](https://raft.github.io/raft.pdf) (USENIX ATC, 2014) | Diego Ongaro & John Ousterhout | Ch. 9: Raft in full |
| ["The Google File System"](https://research.google/pubs/the-google-file-system/) (SOSP, 2003) | Ghemawat, Gobioff, Leung | Ch. 5: distributed persistence, replication |
| ["The Ubiquitous B-Tree"](https://dl.acm.org/doi/10.1145/356770.356776) (ACM Computing Surveys, 1979) | Douglas Comer | Ch. 5: why B-trees are shaped the way they are |
| ["Consistent Hashing and Random Trees"](https://dl.acm.org/doi/10.1145/258533.258660) (STOC, 1997) | Karger et al. (MIT) | Ch. 7: consistent hashing ring |
| ["CAP Twelve Years Later"](https://www.infoq.com/articles/cap-twelve-years-later-how-the-rules-have-changed/) (IEEE Computer, 2012) | Eric Brewer | Ch. 8: CAP theorem |
| ["Consistency Tradeoffs in Modern Distributed Database System Design"](https://www.cs.umd.edu/~abadi/papers/abadi-pacelc.pdf) (IEEE Computer, 2012) | Daniel Abadi | Ch. 8: PACELC theorem |
| *Computer Networks* (4th ed.) | Andrew Tanenbaum | Ch. 1: "never underestimate the bandwidth of a station wagon full of tapes" |
| [LMAX Disruptor / Mechanical Sympathy](https://mechanical-sympathy.blogspot.com) | Martin Thompson | Ch. 1: mechanical sympathy concept |
| [Snowflake ID](https://blog.twitter.com/engineering/en_us/a/2010/announcing-snowflake) (Twitter Engineering Blog, 2010) | Twitter Infrastructure Team | Ch. 7: globally unique sortable IDs |
| [Amdahl's Law](https://en.wikipedia.org/wiki/Amdahl%27s_law) (AFIPS, 1967) | Gene Amdahl | Ch. 2: parallelisation ceiling |
| [Little's Law](https://en.wikipedia.org/wiki/Little%27s_law) (Operations Research, 1961) | John D.C. Little | Ch. 1 & 2: queuing math |
| [CRDTs](https://hal.inria.fr/inria-00555588/document) (INRIA, 2011) | Shapiro, Preguiça, Baquero, Zawirski | Ch. 8: conflict-free replicated data types |
| ["Exponential Backoff and Jitter"](https://aws.amazon.com/blogs/architecture/exponential-backoff-and-jitter/) (AWS Blog, 2015) | Marc Brooker (AWS) | Ch. 12: jitter strategies and empirical results |

---

## Table of Contents

1. [The Physics of Software](#1-the-physics-of-software)
2. [Master the Math of Scale](#2-master-the-math-of-scale)
3. [The Cost of Communication](#3-the-cost-of-communication)
4. [The Anatomy of a Request](#4-the-anatomy-of-a-request)
5. [The Physics of Persistence](#5-the-physics-of-persistence)
6. [The Taxonomy of Storage](#6-the-taxonomy-of-storage)
7. [Sharding](#7-sharding)
8. [CAP Theorem & PACELC](#8-cap-theorem--pacelc)
9. [Distributed Consensus & Raft](#9-distributed-consensus--raft)
10. [Caching](#10-caching)
11. [Asynchronous Systems — Kafka vs RabbitMQ vs SQS](#11-asynchronous-systems--kafka-vs-rabbitmq-vs-sqs)
12. [The Mathematics of the Second Attempt](#12-the-mathematics-of-the-second-attempt)

---

## 1. The Physics of Software
📺 [Watch on YouTube](https://www.youtube.com/watch?v=dDOKu20juEc)

### Core Thesis
Stop thinking in tools (load balancers, databases, caches). Start thinking in **latencies, throughput, and physical constraints**. If you don't understand the hardware underneath your code, your abstractions will leak and your system will fail.

### The Latency Table — Periodic Table of System Design

> We had a high-throughput ingestion service. Best-practice architecture: distributed cache, microservices layer, the whole deal. Under heavy load, latency spiked to 500ms. Junior engineers said "we need more nodes, shard the database." When we looked at the telemetry, we found something embarrassing. Our *fast* distributed cache was the bottleneck. Developers had made 50 small network calls to the cache for every user request. In their heads, cache = fast. But in the world of physics, network = slow. They were fighting the speed of light — and the speed of light was winning.

Scale: _1 CPU cycle = 1 second of human time_ (3 GHz → ~0.3 ns/cycle)

| Event | Real Time | Human-Scale Equivalent |
|---|---|---|
| L1 cache hit | ~0.5 ns | 0.5 s — grab a pen from your hand |
| L2 cache hit | ~4 ns | 4 s — reach across the desk |
| L3 cache hit | ~10 ns | 10 s — walk to the shelf |
| RAM fetch | ~100 ns | 1.5–2 min — walk to a library |
| SSD read | ~100 µs | 2–6 days |
| HDD read (spinning) | ~5–10 ms | 5 months |
| Data center network round trip | ~0.5 ms | 11 days |
| Cross-continent round trip (SF→London) | ~150 ms | 15 years |

**First Principle: Data has distance.** Treat a local variable and a network call as fundamentally different physical events, not just "slow vs fast function calls."

### Mechanical Sympathy

Term coined by racing driver Jackie Stewart: to be a great driver, you must have sympathy for how the machine works.

**Sequential vs Random I/O:**
- HDDs have a physical read arm — random access requires physical movement (seek time), sequential does not.
- SSDs have no moving parts, but still prefer sequential access because of how NAND flash pages and erase blocks work.
- **Why it matters:** LSM-tree databases (Cassandra, RocksDB) convert random writes into sequential appends — they are mechanically sympathetic. B-tree databases require random page updates — more expensive on writes.

### Latency vs Bandwidth — The Pipe Problem

- **Latency:** How long a single bit takes to travel from A to B. Governed by the speed of light. Cannot be improved without physically moving servers closer together.
- **Bandwidth:** How much data can flow through the pipe per unit of time. Can be increased by buying more capacity.

> _"Never underestimate the bandwidth of a station wagon full of tapes hurtling down the highway."_

A Boeing 747 loaded with 15 PB of hard drives from New York to London has terrible latency (8 hours) but extraordinary bandwidth. The internet cannot beat it on throughput.

**Design question:** Are you latency-bound or bandwidth-bound?
- High-frequency trading → latency-bound. Every microsecond is money. Use the shortest physical path.
- Video streaming → bandwidth-bound. A 200ms delay on first bit is fine as long as the stream sustains throughput.

Solving a latency problem with more bandwidth is wasting money.

### Little's Law

`L = λ × W`

- **L** = number of requests in flight in the system at any time
- **λ** = arrival rate (requests/sec)
- **W** = average processing time (latency)

**Implication:** If W increases (slow DB), L must increase. But L is bounded by physical resources (RAM, open connections, threads). When L hits the physical cap, the system queues. As the queue grows, W grows for the next user. This is a **positive feedback loop of death** — systems don't slow down gracefully, they fall off a cliff suddenly.

**Senior engineer behavior:** Monitor λ and W independently. If W creeps up while λ is stable, the system is approaching a wall. Add capacity (increase max L) or optimize code (decrease W).

### Economics of Storage

Every cloud resource rental is a physical trade-off:

| Medium | Relative Cost / GB |
|---|---|
| RAM (in-process) | ~100× |
| SSD / NVMe | ~10× |
| HDD / cold storage (S3 Glacier) | 1× |

Keeping cold data in Redis is like renting a Manhattan penthouse to store cardboard boxes. A senior architect's job is to **align the value of data with the cost of the physics required to store it**.

At FAANG scale: a 1% efficiency gain in RAM usage = $10M/year in data center costs.

### The 5 Questions Before Drawing a Box

1. **Latency** — How far does data need to travel?
2. **Throughput** — How wide is the pipe?
3. **State** — Is the work sequential or random?
4. **Math** — What does Little's Law say about capacity?
5. **Cost** — Is the physical medium worth the business value?

If you can answer these, the architecture draws itself.

---

## 2. Master the Math of Scale
📺 [Watch on YouTube](https://www.youtube.com/watch?v=04ip8kPZXsM)

### The Myth of the Average

> We were monitoring a new service closely. The dashboard showed a beautiful flat line — 100ms average latency. We were high-fiving each other. Then support tickets started coming in. Users said the site felt broken. We looked at the average again: still flat as a pancake. It took us 3 hours to realize we were looking at the wrong number. While the average user was having a great time, one out of every 100 users was experiencing 15 seconds. Because we were watching the mean, we were blind to the suffering of 1% of our audience. At our scale, 1% was 10,000 people.

A dashboard showing flat 100ms mean latency can hide 1% of users experiencing 15-second responses. At 1B requests/day, a P99.9 failure (1-in-1000) happens **1 million times per day**. It's not an outlier — it's a permanent feature of the system.

**Stop monitoring mean latency. Monitor distributions.**

### Percentiles

| Percentile | Meaning |
|---|---|
| P50 (median) | What the typical user experiences |
| P95 | Slowest 5% of requests |
| P99 | Slowest 1% — the "tail" |
| P99.9 | Slowest 0.1% |

Your eyes should skip P50 and lock on **P99 and P99.9**.

### Tail Latency Amplification

This is why microservices can suddenly feel like molasses.

**Math:** A single service with P99 = 100ms means only 1% of requests are slow. Now build a page that fans out to 100 microservices in parallel.

```
P(all fast) = 0.99^100 ≈ 0.366
P(at least one slow) ≈ 63.4%
```

If your page depends on 100 services each with 1% slowness, **64% of your users** see a slow page. The tail of each component becomes the median of the whole.

**Consequence:** As you increase the number of components, the P99 of components becomes the P50 of the system. The exception becomes the rule.

**FAANG-level principle:** Optimize for **variance**, not raw speed. A service that is always 50ms is better than one that is usually 10ms but occasionally 500ms. Predictability beats peak performance in distributed systems.

### Throughput vs Latency — The Highway Analogy

- **Latency** = time for one car to drive A→B
- **Throughput** = cars passing a point per hour

They coexist peacefully up to ~70% utilization. Above that, the **knee of the curve** kicks in: a single brake tap cascades into a 10-minute tail for everyone behind.

**Why FAANG runs at 60-70% utilization:** The idle 30% is the insurance policy that keeps P99 from exploding during traffic spikes. Feels wasteful to juniors; is load-bearing to seniors.

### Amdahl's Law

> The speedup of a task is limited by its serial fraction.

`Max speedup = 1 / (s + (1-s)/n)`

Where `s` = serial fraction, `n` = number of processors.

If 5% of your code is serial (one DB lock, a global counter), the maximum possible speedup with infinite cores is **20×**. Throwing a million-dollar supercomputer at it won't give you 21×.

**Staff-level insight:** Don't make the fast parts faster. Find the serial bottleneck and shrink it. A 5% serial section in a global system is the ceiling of your company's growth.

### Succession of Bottlenecks

When you fix a performance problem, you don't eliminate it — you move it:

1. Slow algorithm → optimize → CPU is fast → now hitting DB hard
2. DB is bottleneck → add cache → DB is fast → now saturating network card
3. Network card upgraded → now hitting lock contention in the kernel

**Goal:** Move the bottleneck to where it's cheapest and easiest to manage. Network bandwidth (buyable) is better than DB lock contention (requires architectural rewrite).

### The Four Golden Signals (Google SRE)

| Signal | What to watch |
|---|---|
| **Latency** | P50, P95, P99 separately. P50 stable + P99 rising = tail/contention problem |
| **Traffic** | Arrival rate λ from Little's Law |
| **Errors** | Always relative to traffic. Errors flat + traffic drops = system failing to be reached |
| **Saturation** | How full is your most constrained resource? |

**Saturation is a leading indicator.** CPU going from 40% → 80% while latency stays flat means you're approaching the knee of the curve. You're inches from an explosion.

> "We are at 85% saturation on the DB connection pool. At current growth, we hit 100% in 2 weeks. At 100%, P99 increases by 500%." — This is how you prevent outages before they happen.

### Hedged Requests (Google Search)

Problem: 1,000 machines fan out per query. Each has 1% chance of being in the P99 slow zone. User is guaranteed a slow experience.

Solution:
1. Send request to first machine
2. Wait for P95 latency (e.g., 10ms)
3. If no response, send identical request to a different replica
4. Take whichever result comes first, cancel the other

**Math:** Both machines must be in slow zone simultaneously: `0.01 × 0.01 = 0.0001` — 100× reduction in tail latency at the cost of ~5% extra throughput.

This is **statistical engineering** — using probability laws to build reliable systems on unreliable components.

---

## 3. The Cost of Communication
📺 [Watch on YouTube](https://www.youtube.com/watch?v=YOR9hAFoe2o)

### The Fallacy of the Local Call

> If an L1 cache hit takes 1 second in human time, a local RAM hit is 3 minutes. But a network call within the same data center is 11 *days*. Imagine if every time you reached for a pen on your desk it took 1 second — but every time you wanted to check your phone, you had to wait 11 days. You would organize your life very differently. You wouldn't check your phone 50 times a day. You would batch your questions. Yet in our microservice architectures, we make these 11-day calls constantly, often inside loops, because the abstraction hides the tax.

Code like `user = db.fetch_user(id)` looks local. It isn't. It sends electrons through copper, through switches, through firewalls, into another machine's kernel. Every network call is a round trip measured in days on the human scale.

### The Network Tax Bill

Every network call incurs multiple taxes stacked on top of each other:

**1. DNS Tax (1–10ms)**
Before the request even begins, the hostname must resolve to an IP. If not cached locally, a recursive lookup travels to root nameservers → TLD server → authoritative server. Each hop is a UDP round trip.

**2. TCP Handshake Tax (1 RTT)**
TCP is stateful. The wire is stateless. Creating the illusion of a connection requires SYN → SYN-ACK → ACK. One full round trip of zero application data. At 50ms RTT = 50ms wasted just saying hello.

**3. TLS Cryptographic Tax (1–2 RTT)**
TLS 1.2 required 2 additional round trips. TLS 1.3 reduced to 1. Plus CPU cost for certificate verification (RSA/elliptic curve math).

**4. Kernel Context Switch Tax**
Your application lives in user space. The network card is managed by the kernel. When data arrives, the kernel copies it from kernel memory to application memory (a syscall). Your CPU stops running app code, switches to kernel mode, moves bytes, switches back. At thousands of requests, more CPU time is spent switching than on business logic.

High-performance networking (DPDK, eBPF) attempts to let applications talk directly to hardware to bypass this tax.

**5. Congestion Tax (random, up to 100× latency increase)**
The network is a shared resource. When a switch gets congested, it drops packets. TCP resends them. Your 1ms request becomes 200ms.

### Serialization: JSON vs Binary

**JSON** requires the CPU to:
- Scan character-by-character for delimiters
- Parse string "42" into integer 42
- Allocate new string objects for every key
- Unknown array sizes require scanning to the closing bracket
- Generates garbage the GC must collect constantly

**ProtoBuf / gRPC:**
- Fields are numbered, not named — no string scanning
- Integers are copied directly as bytes
- 30-40% less CPU spent on serialization at scale
- Used by Google for almost all internal communication

**FlatBuffers (Netflix, game dev):**
- Zero-copy: data on wire = data in RAM layout
- No deserialization step — map the network buffer to a pointer and use it

**Apache Arrow (big data):**
- Standard memory layout: disk format = wire format = RAM format
- zerocopy deserialization — bytes from network card are mapped directly into application memory
- Eliminates the serialization tax entirely for columnar data

### Speed of Light Is a Hard Floor

SF → London distance: ~8,500 km. Round trip: ~17,000 km.  
Light in fiber (refractive index ~1.5): ~200,000 km/s.  
**Minimum physics-limited RTT: ~85ms.** Cannot be beaten without moving servers.

**TCP + TLS 1.2 compound cost (SF→London):**
- TCP handshake: 1 RTT = 85ms
- TLS 1.2: 2 RTT = 170ms
- HTTP request: 1 RTT = 85ms
- **Total before first byte: 340ms**

A human notices delay at >100ms. We've tripled that before running a single query.

**QUIC / HTTP3** addresses this by combining TCP and TLS handshakes into one (or zero for repeat connections with 0-RTT). Reduces 340ms → 170ms or even 85ms.

### Design Principles for Communication

**Primary principle:** The most efficient way to communicate is to not communicate at all.

If communication is unavoidable:

1. **Batch over multiple calls:** Fetch entire user profile in one call, not name + avatar + bio separately. Send 1,000 DB inserts as one batch, not 1,000 individual inserts.

2. **Chunky, not chatty APIs:** A chatty API makes clients ask many small questions. A chunky API lets the client say "give me everything I need for the home screen" — server assembles it with low-latency local DB access and returns one dense package.

3. **Co-locate what communicates:** If service A and service B are in constant high-frequency communication, they should be one service. Microservice splits turn free local function calls into expensive network calls.

4. **Reuse connections (HTTP/2 multiplexing):** Discord switched from REST+JSON to gRPC, enabling HTTP/2 multiplexing — 50 requests over one TCP connection, paying the handshake tax once instead of 50 times.

---

## 4. The Anatomy of a Request
📺 [Watch on YouTube](https://www.youtube.com/watch?v=kt1tW0El6Gg)

### The Complete Journey of a Single Request

From `netflix.com` typed in a browser to application code receiving a clean object:

```
Browser (UTF-8 string in memory)
  ↓ OS syscall (context switch to kernel)
  ↓ Packet construction (TCP header + IP header + Ethernet frame = 54 bytes overhead per 1500-byte MTU packet)
  ↓ NIC converts to radio waves (Wi-Fi) or electrical pulses (Ethernet)
  ↓ Router → ISP
  ↓ DNS resolution
  ↓ BGP routing through ~70,000 autonomous systems
  ↓ Anycast → edge server
  ↓ TLS termination at edge
  ↓ WAF (deep packet inspection)
  ↓ L4 load balancer (blind, IP/port only)
  ↓ L7 load balancer (smart, reads HTTP headers)
  ↓ API Gateway (auth, rate limiting, protocol translation)
  ↓ Your application code
```

### DNS — Distributed Hierarchical Database

**Not a phone book.** A distributed, hierarchical, eventually consistent database based on "I don't know, go ask my boss."

**Resolution chain:**
1. Check local OS cache
2. Ask recursive resolver (ISP or Cloudflare 1.1.1.1)
3. Resolver → Root nameserver (13 logical roots, A–M): "Who manages `.com`?"
4. Root → TLD server: "Who manages `netflix.com`?"
5. TLD → Authoritative nameserver: "What's the IP for `netflix.com`?"
6. Authoritative → Returns A record (e.g., `54.237.226.164`)

**Protocol:** UDP on port 53 (TCP handshake cost would be prohibitive). UDP is unreliable — lost DNS packets = browser spinner before the request even starts. DNS is the **silent killer of P99s**.

**TTL trade-off:**
- High TTL (24h): Fast (cached everywhere), but agility is lost. If the DC catches fire, you're stuck for 24h.
- Low TTL (60s): Agile, but every user pays the DNS tax every minute.

**GeoDNS:** Authoritative server inspects the user's source IP and returns the IP of the nearest data center. DNS is the **first load balancer in your stack**.

### BGP — The Internet Runs on Gossip and Trust

The internet is ~70,000 independent Autonomous Systems (AS). BGP is the protocol by which they announce reachability to each other. BGP is **policy-based, not performance-based.** A path that costs less money wins over a path that's 4× faster.

**BGP leaks:** Occasionally an AS accidentally advertises that it has the best path to Google. Half the world's traffic tries to route through a fiber cable in a basement. The internet breaks.

**Anycast:** Give the same IP address to 100 data centers worldwide. When a packet enters the BGP wilderness, routers route it to the physically nearest instance of that IP. This is how Cloudflare's `1.1.1.1` feels fast globally. **Not faster speed of light — closer destination.**

### The Edge

**Why it exists:** TLS handshakes are expensive. SF user + Virginia server = 450ms for handshake before one byte of data. An edge server in SF reduces the handshake to 10ms. The edge maintains a persistent warm connection to Virginia. **We are caching the connection tax.**

If you're not terminating TLS at the edge, you are penalizing global users before they've reached your firewall.

### WAF — Web Application Firewall

The bouncer that performs deep packet inspection (DPI). Scans request payload against thousands of regex rules for SQL injection, XSS, etc.

**Physics reality:** Every regex rule is a CPU operation. A WAF adding 40ms while the DB query was optimized to save 5ms is a common trap. Move WAF rules as far upstream (to edge hardware) as possible so clean traffic passes the main load balancers unburdened.

### L4 vs L7 Load Balancing

| | L4 (Transport) | L7 (Application) |
|---|---|---|
| What it sees | IP address + port | HTTP headers, URL paths, cookies |
| What it can do | Round-robin, IP hash | Route `/api/v2` to Go service, `/images` to S3 |
| Speed | Extremely fast, millions req/s, near-zero latency | Slower — must buffer + parse request |
| Use case | Front line, DDoS protection, raw volume | Smart routing, A/B testing, protocol translation |

**Best practice:** L4 at the very front for raw volume protection, then L7 behind it for smart routing.

### API Gateway

The lobby of your application. Responsibilities:
- **Authentication:** Is this JWT valid?
- **Rate limiting:** 500 requests this second from this user? Kill it.
- **Protocol translation:** REST/JSON → gRPC for internal services

**Why not in application code?** Security. A malformed JWT hitting your Python app can crash it. A gateway written in high-performance C++/Rust (Envoy, Kong) drops bad requests before they touch expensive application memory.

---

## 5. The Physics of Persistence
📺 [Watch on YouTube](https://www.youtube.com/watch?v=RAuIWs3ne9g)

### The Volatile Mind Problem

RAM is a dream that ends when the power cord is pulled. Every variable, object, and state vanishes in milliseconds. To build systems that matter — banking, medical records — we must commit data to durable storage.

**The central tension of all system design:** We want data to be persistent (survive crashes) but apps to feel fast. These goals are opposed by the laws of physics. The disk is orders of magnitude slower than RAM.

### The OS Lie: Buffered I/O

> Most of your time as a developer is spent in what I call the *volatile mind* of the computer. When you create a variable `user_id = 10`, that data feels very real. You can see it in your debugger. You can print it. But it's not really there. It's a ghost. It lives in RAM. And RAM is a dream that ends the moment the power cord is pulled. If the electricity stops flowing for even a millisecond, every variable, every object, every state in your application just vanishes. Gone. Like it never happened.

```python
with open('file.txt', 'w') as f:
    f.write('hello world')  # Returns success. Data is NOT on disk yet.
```

The OS knows disk is slow. It takes your data, puts it in the **page cache (RAM)**, and says "I'll write it to disk later." If power dies in the next millisecond, your data is gone. This is **buffered I/O**.

**`fsync()`** — the moment of truth:
- Forces the OS to flush bytes to physical hardware
- Blocks your entire process until hardware confirms physical cells have changed
- The most expensive call in software engineering
- With `fsync` after every write: ~100 writes/second max throughput

### Write-Ahead Log (WAL)

How Postgres achieves both durability and thousands of transactions/second:

Instead of updating complex data structures (B-tree with 5 indexes) on every write, **append the change to a sequential log file**:

```
User 5 changed name to Andre  → append
User 10 deleted account       → append
```

Appending to the end of a file is the **fastest thing a disk can do** (sequential, no seeking).

If the DB crashes, replay the WAL from the last known good state. The WAL is the source of truth.

**Chef analogy:** Think of a busy restaurant. You don't update the final inventory book every time you use a single egg — you'd spend all your time walking to the office to write in the book. Instead, you scribble "used one egg" on a notepad on the counter. That notepad is the WAL. At end of night, when the kitchen is quiet, you reconcile the notepad with the big book. The notepad is fast. The big book is slow. Scribble "used 1 egg" on a notepad (WAL). At end of night, reconcile the notepad with the big book.

### SSD Physics — Why Even SSDs Lie

- **NAND flash cells cannot be overwritten** — they must be erased first
- **Read/write granularity:** 4KB or 8KB pages
- **Erase granularity:** 2MB blocks

To change 1 byte in the middle of a 2MB block:
1. Read entire 2MB block into RAM
2. Modify the byte in RAM
3. Erase the entire 2MB block
4. Write the 2MB block back

This is **write amplification** — you wanted to write 1 byte, the disk moved 2MB.

**Flash Translation Layer (FTL):** A tiny computer inside every SSD that constantly remaps logical addresses to physical cells to distribute wear. SSD cells die after a finite number of program-erase cycles. When you write to sector 10, the FTL may actually store it on cell 5000.

**Conclusion:** Sequential writes are still better on SSDs. Random writes trigger FTL garbage collection and performance drops.

### B-Tree — King of Read-Optimized Indexes

A B-tree is designed around one fact: **the disk reads in pages** (4KB or 8KB). Like a delivery truck — doesn't matter if it carries one envelope or 50 boxes, it still has to drive.

A B-tree is therefore **fat (high fan-out)** — each node may have 500 children instead of 2.

**Math:**
- Layer 1 (root): 1 node → 500 pages
- Layer 2: 500 nodes → 250,000 pages
- Layer 3: 250,000 nodes → 125 million pages
- Layer 4: 125M nodes → **62.5 billion rows**

**4 disk trips to find any row in 62 billion.** That's 30–40ms — the time to blink.

**Weakness:** Updates require random writes — find the specific page, read it into RAM, modify it, write it back. Under heavy write load, the disk bounces around randomly. Slow for write-intensive workloads.

### LSM Tree — King of Write-Optimized Indexes

Used by Cassandra, RocksDB, MongoDB (WiredTiger), LevelDB.

**Core insight:** What if we never do a random write? Only sequential writes?

**How it works:**
1. Incoming writes go to a **MemTable** (sorted list in RAM) — lightning fast
2. Simultaneously, the write is appended to a WAL on disk (sequential) for durability
3. When MemTable fills (~64MB), it's frozen and flushed to disk as an **SSTable** (Sorted String Table) — immutable, sequential write
4. SSTables are **never modified** — new versions are new files
5. **Bloom filters** in RAM tell you instantly if a key is definitely NOT in a given SSTable — saves disk trips
6. Background **compaction** merges small SSTables into larger ones (merge sort), discarding old deleted versions

**Trade-off read for writes.** Reads may need to check multiple SSTables. Bloom filters and compaction minimize this.

### The RUM Conjecture

**R**ead, **U**pdate, **M**emory — you can only optimize for two at once.

- **B-tree:** Optimized for Read (shallow tree, few disk trips). Updates are expensive (random writes).
- **LSM tree:** Optimized for Update (sequential appends). Reads are more expensive (multiple SSTable checks).

**Choosing:**
- High-write system (logging, timeseries): LSM tree
- High-read system (banking balances): B-tree

### Bit Rot

The universe is messy. Causes of silent data corruption:
- **Cosmic rays:** High-energy particles flip individual transistors
- **Electrical decay:** Flash cell charge leaks out over years

Modern databases/filesystems (ZFS) calculate a **checksum (hash) of every page** and store it alongside. On read, recalculate hash. Mismatch = disk lied.

> **First principle of reliability:** Hardware is a suggestion. Software is the enforcement.

### Distributed Persistence — The GFS Model (2003)

**Google File System observations:**
- Component failures are the norm, not the exception
- Solution: expect to die every day and design for it

**Approach:**
- Files broken into 64MB chunks
- Each chunk stored on **3 different machines in 3 different racks**
- One rack loses power → two copies still alive
- Two racks lose power → one copy still alive

**Why 3 copies?** The math of fault tolerance with cost constraints.

**Consistency problem with 3 copies:** Copy 1 says $100, copy 2 says $100, copy 3 says $50 (network slow). Which is the truth? This is not just a disk problem — it's a **coordination problem**. Solved by consensus algorithms (Raft, Paxos — see chapter 9).

### Persistence as a Spectrum

| Storage | Risk Level | Speed |
|---|---|---|
| RAM | High (loses on power cut) | Fastest |
| Local SSD, standard write | Medium (safe on app crash, maybe not OS crash) | Fast |
| Local SSD, fsync | Low (on physical metal) | Slow |
| 3× replicated across 3 data centers | Near zero | High latency, expensive |

**Your job:** Look at each piece of data and ask "what is the cost of losing this byte?"
- A like on a post → LSM + eventual consistency is fine
- A log message → OS buffer is fine
- A $10,000 bank transfer → fsync + B-tree + 3 replicas confirmed before showing the green checkmark

---

## 6. The Taxonomy of Storage
📺 [Watch on YouTube](https://www.youtube.com/watch?v=mhpinZnH7xI)

### First Principle: Choose by Access Pattern

Don't choose a database based on how data looks. Choose it based on **how you intend to query it**.

Write out the 5 most common questions your app will ask, then choose the model that answers them fastest.

### Relational Model (SQL)

**Origin:** Edgar Codd, IBM, 1970. "What if we treat data as mathematical relations?" Normalized tables, primary keys, foreign keys.

**Core principle of normalization:** Store every fact exactly once. If Andre's address is in 5 places and he moves, you must update all 5. Miss one = the database is lying.

**ACID guarantees:**
- **A**tomicity — transaction either fully commits or fully rolls back
- **C**onsistency — database moves from one valid state to another
- **I**solation — concurrent transactions don't interfere
- **D**urability — committed data survives crashes

**The Join Tax:** Flexible ad-hoc queries require joining across tables = random I/O across disk pages. As data grows to billions of rows, joins become extremely expensive.

**Impedance mismatch:** Code thinks in objects/trees; SQL thinks in flat tables. ORM frameworks exist to bridge this gap but add overhead.

**Schema-on-write:** You must define columns before saving. This enforces discipline.

### Key-Value Stores (Redis, DynamoDB)

The simplest possible taxonomy: a giant distributed hashmap.

**How it works:** Hash the key → O(1) lookup → exact disk location → return value. No joins, no scanning.

**Performance:** Fastest possible reads. Sub-millisecond lookups.

**Trade-off (the query tax):** You can only retrieve data by exact key. You cannot do "show me all users who bought coffee" unless you built a specific key for it. No range scans, no aggregations.

**Use when:** You need blazing fast lookup by a known key. Shopping carts, session data, rate limiting counters, pre-computed recommendation feeds.

### Document Stores (MongoDB, CouchDB)

**Motivation:** Impedance mismatch frustration. "Why can't I just save the whole user object as one JSON blob?"

**Data locality:** Everything related to a user — profile, settings, last 5 orders — stored together in one physical location on disk. One disk trip = full user data returned. No joins.

**Hidden tax (the relationship tax):** Trading normalization for locality. If user's address is stored inside both the user document and the invoice document, and the user moves — update both or data is inconsistent. If user changes profile picture, update every post document where they commented.

This is **managing the join in application code** — complexity shifts from DB to your code.

**Use when:** Data is self-contained and has few relationships. Blog posts, product catalog, user profiles (when not heavily referenced across collections).

**Avoid when:** Data is highly interconnected. Social graphs, financial transactions, anything with complex referential integrity needs.

**Schema-on-read:** The schema always exists — it's either in the DB or in your application code. The hidden cost of "no schema" is 5 years of `if user.zip_code or user.postal_code` scattered across your codebase.

### Graph Databases (Neo4j)

In relational databases, relationships are secondary (foreign keys in columns). In graph databases, **relationships (edges) are first-class citizens** — physically stored as pointers.

**Power query:** "Find me a friend-of-a-friend who likes the same music and has worked at the same company." In SQL: 5–6 joins, minutes at scale. In a graph DB: walks physical pointers, speed depends on your local neighborhood size, not total DB size.

**Use when:** The relationships between facts are more important than the facts themselves. Social networks, recommendation engines, fraud detection, knowledge graphs.

### NewSQL (CockroachDB, Google Spanner)

**Observation:** People love SQL and ACID guarantees but hate the scaling limitations of single-node SQL.

**Approach:** Use distributed consensus (Raft) to give you a SQL interface that lives on thousands of servers simultaneously.

**Trade-off:** Individual write latency is always higher than single-node Postgres because servers must coordinate. Write in CockroachDB > write in single Postgres. You trade per-operation speed for global scale.

### Vector Databases (Pinecone, Milvus, pgvector)

New taxonomy driven by AI revolution. Don't store facts — store **embeddings** (mathematical representations of meaning in high-dimensional space).

**Queries:** "Find images visually similar to this image" or "Find text semantically similar to this sentence." Standard DBs are useless here. Need approximate nearest neighbor (ANN) search in 1,000+ dimensional space.

**Access pattern still dictates the model.** The pattern "finding meaningful similarity" required a new storage model.

### Decision Framework

| Query Type | Best Model |
|---|---|
| Give me this specific thing by ID | Key-value |
| Give me this thing and all its nested details | Document |
| Give me aggregates/summaries across many rows | Relational SQL |
| How is A connected to B? | Graph |
| Millions of high-accuracy balance updates | SQL or NewSQL |
| Find things similar to this | Vector DB |

**Default recommendation:** Start with Postgres. It's good enough at almost everything — has JSON support (acts like document store), indexed lookups (acts like key-value), joins (no-SQL can't), full ACID. Only migrate when you can prove with benchmarks that the join tax is killing production performance.

### Polyglot Persistence

Modern large systems use the right taxonomy for each access pattern:

**Netflix example:**
- User profiles (name, email) → Postgres (ACID integrity)
- Viewing history (massive firehose) → Cassandra (high write throughput)
- Personalized recommendations → Redis (sub-millisecond key-value lookups)
- Content relationship graph → Graph DB

---

## 7. Sharding
📺 [Watch on YouTube](https://www.youtube.com/watch?v=X72epD9Qn3U)

### The Vertical Wall

> Imagine a startup with a note-taking app. One Postgres instance on a T3 micro — $10/month, 100 users, database asleep 99% of the time. Then you get featured on Hacker News. Suddenly 10,000 users. CPU spikes. Latency climbs. What do you do? The most logical, rational thing an engineer can do: you pay Bezos more money. Click a button, upgrade to M5 large. Boom — CPU drops, latency vanishes. You feel like a genius. You can keep doing this for a long time. But eventually, physics wins.

**Vertical scaling (scale up):** Buy a bigger server. T3 micro → M5 large → 24xlarge → 4TB RAM machine.

**Why it hits a wall:**
- A processor with 10,000 cores does not exist
- 500 PB of NVMe cannot attach to one motherboard (bus bandwidth limit)
- Cost is exponential: 2× faster = 5× more expensive
- When a 4TB RAM server crashes, it takes an hour to restart (reading transaction logs)

**Horizontal scaling (scale out):** Buy 1,000 cheap commodity servers and tie them together. Theoretical limit: infinite. But now — where does each piece of data live?

### Shard Keys — The Most Critical Decision

The shard key is the dimension along which data is partitioned. Common choices:
- **User ID** — all of user X's data on one shard
- **Tenant ID** — all of company Y's data on one shard (multi-tenant SaaS)
- **Geography** — all European users on shard 3
- **Time** — all data from 2023 on shard 4

**Wrong key = system implosion.** Companies have failed from this decision.

### Range-Based Sharding

Natural ordering: user IDs 1–1M on shard 1, 1M–2M on shard 2, etc.

**Superpower:** Range queries are efficient. "All users who signed up between ID 1.5M and 1.6M" → hit exactly one shard.

**Fatal flaw — hotspots:** Data is rarely uniform. If sharding by creation date, shard for "today" receives 100% of writes. All other shards sit idle. You've scaled storage, not write throughput.

**Library analogy:** Split by first letter. A–M vs N–Z. But S (Smith, Stevenson, Shakespeare) vastly outnumbers X, Y, Z. Shelf 1 overflows while shelf 2 is empty.

### Hash-Based Sharding

```
shard = hash(shard_key) % number_of_servers
```

Hash functions produce pseudo-random outputs. Sequential users scatter across different servers uniformly. Solves hotspots.

**Fatal flaw — resharding storm:** Adding one server changes n from 4 to 5. The key-to-shard mapping for `(n-1)/n` of all data changes.

At n=5: 80% of all data must move. At n=100: 99% of data must move. 100TB database + add one server = 80TB migrating across your network. Bandwidth saturated, disk I/O saturated, requests fail during migration.

### Consistent Hashing

Invented at MIT in the late 1990s. Powers Cassandra, DynamoDB, Discord.

**Mental model:**
1. Hash function output range is laid out as a **ring** (e.g., SHA-1 = 0 to 2^160, wrapping around)
2. Servers are placed on the ring by hashing their names/IDs
3. Each data item is hashed to a point on the ring
4. The **rule:** walk clockwise until you hit a server — that server owns the data

**Adding a server:** Place it on the ring. Only data in the arc between the new node and its predecessor moves. All other data is unaffected.

**Math:** With n servers, adding one moves **1/n of data** on average. At 100 servers: only 1% of data moves. Scaling becomes a non-event instead of a traumatic outage.

**Virtual nodes (vnodes):** Each physical server is represented by 100+ virtual nodes scattered around the ring. Law of large numbers ensures even distribution even with a small number of physical servers.

### The Hotkey Problem (Celebrity Problem)

Consistent hashing distributes keys uniformly across servers. But what if one key is astronomically hotter than others?

**Example:** Justin Bieber tweets. 100M followers. Potentially millions of fan-out operations hitting the single shard that owns the Bieber key. That shard melts regardless of how many servers are in the cluster.

**Solution — key splitting:**
```
candidateA_votes → split into candidateA_0 through candidateA_9
```
On write: pick random suffix 0–9. Consistent hashing distributes these to different servers.

**Cost:** On read, must query all 10 sub-keys and sum in application code. Trade: writes 10× faster, reads 10× slower (read-write amplification). Only worth it for heavily write-skewed hot keys.

### Globally Unique IDs Without Coordination

In a sharded system, there is no central counter. Auto-increment breaks. UUID v4 is random → B-tree hates random primary keys (random inserts in the middle of the tree = random write I/O).

**Snowflake ID (invented by Twitter):**

```
[sign bit: 0][timestamp: 41 bits][machine ID: 10 bits][sequence: 12 bits]
```

- **Timestamp at the front:** IDs are monotonically increasing over time → B-tree can always append to the end → sequential write I/O
- **Machine ID in the middle:** Two different servers can never generate the same ID → no coordination needed
- **Sequence:** Local counter that resets every millisecond → multiple IDs per millisecond per machine

69 years of IDs. 1,024 shards. 4,096 IDs per millisecond per shard.

**Use ULID or Snowflake IDs in distributed systems. Never UUID v4 as a primary key.**

### Zero-Downtime Migration Playbook

How to shard a live single-DB system with no downtime:

**Phase 1 — Double Write:**
Modify app to write to BOTH old DB and new sharded cluster. New cluster is best-effort (wrapped in try/catch). Old DB remains authoritative. New data flows to both.

**Phase 2 — Backfill:**
Background worker iterates old DB, copies each row to new cluster. Use timestamps/version numbers to prevent overwriting newer data with older data (race condition).

**Phase 3 — Verification (Paranoia Phase):**
Script picks random rows, reads from both DBs, compares. Do NOT proceed until 100% consistency confirmed. Fix any bugs, re-run backfill.

**Phase 4 — Read Switch:**
Feature flag flips reads to new DB. Keep writing to both. Safety: if new DB explodes, flip flag back — old DB has latest writes, zero data loss.

**Phase 5 — Write Switch:**
After a week of stable reads, remove dual-write code. Decommission old DB. Champagne.

**Pattern applies universally:** SQL → NoSQL migrations, monolith → microservices, re-sharding. This is how it's always done.

### When NOT to Shard

Sharding loses:
- ACID transactions across shards
- Simple SQL joins (must join in application code)
- Operational simplicity (backup 100 DBs instead of 1)
- Simple index management

Before sharding, exhaust:
1. Delete old/unused data
2. Optimize SQL queries and indexes
3. Add a caching layer (Redis)
4. Upgrade to a bigger server

Sharding is not a feature. It's a necessary evil. **Complexity is the tax you pay for scale.**

---

## 8. CAP Theorem & PACELC
📺 [Watch on YouTube](https://www.youtube.com/watch?v=Ub9yZucpwC0)

### The Notebook Analogy

One notebook = one DB. Consistent, available, simple. Scale to 10 notebooks with 10 people. Person B is asked for the balance while the hallway (network) is blocked. They can either:
- Say "I don't know" → lose **availability**
- Say the last known balance → lose **consistency**

This is the heart of CAP.

### Definitions

**Consistency (C):** Linearizability. Every read returns the most recent write or an error. The entire distributed system acts as a single machine with one truth. No stale reads, ever.

**Availability (A):** Every request receives a non-error response. The system never refuses a user, even if it can't guarantee freshness. Measured in nines (99.999%).

**Partition Tolerance (P):** The system continues operating despite arbitrary network failures between nodes.

### The Real Choice

**CA is not a valid choice.** Partitions will happen. Backhoes cut fiber. Switches overheat. Software bugs cause packet loss. In a distributed system (more than one machine), you must tolerate partitions. Period.

**The real binary choice is:** When a partition occurs, do you choose **C** or **A**?

- **CP (Consistency over Availability):** When nodes can't communicate, shut down rather than serve stale data. Prioritize truth over uptime.
- **AP (Availability over Consistency):** When nodes can't communicate, keep serving. Accept that some nodes will serve stale data temporarily.

**Important:** A partition isn't just a cut cable. A partition is any time the delay between nodes exceeds your timeout. Because we want fast apps, we set low timeouts, which means we are constantly triggering mini-partitions.

### CP Systems

> You have $100. You go to an ATM in New York and try to withdraw $100. At the exact same millisecond, your spouse goes to an ATM in Los Angeles and tries to withdraw $100. If the bank prioritizes availability, both ATMs might say "sure, here's your cash" — because they can't talk to each other fast enough to realize the money is being double-spent. The bank is now out $100. The bank hates this. So the bank chooses CP: the LA ATM can't reach NY headquarters to lock your account, so it says "service temporarily unavailable." User is annoyed. Availability is gone. But the truth of the balance is preserved.

**Use cases:** Banks, stock exchanges, inventory systems where a wrong answer costs real money.

**Example:** Two ATMs trying to withdraw the same $100 simultaneously. A CP system locks the account at the primary. If the LA ATM can't reach NY headquarters during a partition, it returns "service temporarily unavailable." User is annoyed, but the bank's balance is accurate.

**Implementation:** Distributed locking, consensus algorithms (Raft, Paxos), quorum writes. A write is not confirmed until a majority of nodes acknowledge it.

### AP Systems

**Use cases:** Social media, content platforms, anything where temporary inconsistency has no business consequence.

**Example:** Instagram like. Does the global infrastructure need to stop and agree before the heart turns red? No. During a partition, Singapore writes the like locally. Queues propagation to Oregon. Oregon sees 10 likes, Singapore sees 11 likes for a few minutes. **Nobody cares.**

**CRDTs** (see below) are the sophisticated version — data structures designed so that out-of-order updates always converge to the same final state.

### PACELC — The Pro Version of CAP

CAP only addresses partition scenarios (rare). What about when the network is healthy?

`PACELC = (Partition → Availability vs Consistency) ELSE (Latency vs Consistency)`

**Even during normal operation, you face a trade-off:**

- **Synchronous replication (PC/EC):** Primary waits for all replicas to confirm before telling the user "success." Safe, but write latency = speed of the slowest replica. If you have a replica in Singapore and you're in London, every write is 200ms.
- **Asynchronous replication (PA/EL):** Primary writes locally, tells user "success," propagates to replicas in background. Fast, but if primary dies before replicas catch up, that data is permanently lost.

**DynamoDB:** AP during partition, EL during normal times.  
**Postgres with synchronous commit:** CP during partition, EC during normal times.

### The Consistency Spectrum

From most to least strict:

**1. Strong Consistency (Linearizability):**
Every read returns the most recent write. Distributed Raft cluster, single-node Postgres. Gold standard. Expensive, slow.

**2. Read-Your-Writes:**
You always see your own latest writes, even if others don't yet. Implemented by pinning a user session to the same DB node for seconds after a write. Prevents "I just saved my bio and the page shows the old one."

**3. Monotonic Reads:**
Once you've seen version N, you'll never see version N-1. Prevents time-travel bug: score shows 10-12, refresh shows 10-10, refresh again shows 10-12. Time only moves forward.

**4. Causal Consistency:**
If Alice posts a question and Bob posts an answer, anyone who sees the answer will also see the question. Respects cause-and-effect ordering.

**5. Eventual Consistency:**
If no new updates are made to a key, all reads will eventually return the same value. Like gossip — eventually everyone in the room knows the secret, but there's a window of inconsistency.

**Engineer's job:** Find the **weakest consistency model your business can tolerate.** Weaker = higher performance + lower cost.

### Conflict Resolution

When AP systems heal a partition, conflicting writes must be reconciled:

**1. Last Write Wins (LWW):**
Compare timestamps. Later timestamp wins, earlier is discarded. Used by Cassandra by default. **Dangerous:** Clock skew is real (server clocks drift). A "later" write may actually be earlier. Silent data loss.

**2. Vector Clocks:**
Logical clock — each node keeps a counter of events it has seen. Can determine: "version A is a descendant of version B" vs "versions A and B are concurrent." If concurrent, don't try to resolve — store both and let the application decide. Amazon's original Dynamo paper: shopping cart might show duplicate items during a conflict. Better to see a duplicate than silently lose one.

**3. CRDTs (Conflict-Free Replicated Data Types):**
Mathematical data structures where concurrent updates always converge to the same result regardless of order or duplication. Sets use union (idempotent, commutative, associative). Used by Figma, Google Docs for real-time collaborative editing without central locking.

### Split Brain

AP system attempts to heal after partition: both halves elected a leader. Both accepted writes. Two diverging databases think they're authoritative. When the network heals — potentially unfixable corruption.

**Defense:** Quorum rules (majority wins), fencing tokens, careful partition detection.

---

## 9. Distributed Consensus & Raft
📺 [Watch on YouTube](https://www.youtube.com/watch?v=xU-7JxwUpLo)

### The Problem

5 machines must act as one. They can only communicate through unreliable tin-can phones (network). Challenges:
- Network partition (string gets cut)
- GC pause (person falls asleep for 20 minutes, then wakes up acting normal)
- Latency (message takes 5 minutes to arrive)

Getting these machines to agree on a single value is arguably the hardest problem in computer science. Old solution: Paxos (notoriously incomprehensible). New solution (2013): **Raft** — designed explicitly to be understandable.

### Leader-Follower Model

**Why not democracy for every write?** A full 5-node election per write would be catastrophically slow.

Solution: elect one **leader** for an extended period. All writes go to the leader. The leader is the source of truth. Followers copy whatever the leader does.

### Node States

Every Raft node is in one of three states:
- **Follower:** Passive. Listening for heartbeats from leader.
- **Candidate:** Attempting to become leader. Launched when heartbeat timeout expires.
- **Leader:** The boss. Accepts writes, replicates to followers.

### Leader Election

**Heartbeats:** The leader broadcasts tiny "I'm still alive" packets to all followers at regular intervals.

**Election timeout:** Each follower has a **randomized** timeout (e.g., 150–300ms). If no heartbeat received within that window, assume leader is dead → declare an election.

**Why randomized?** If all timeouts were equal (say 500ms), all followers would wake up simultaneously → split votes → nobody wins. Randomization ensures one node wakes up first.

**Election process:**
1. Node increments its **term** counter (logical time — equivalent to an "election year")
2. Node votes for itself
3. Sends RequestVote to all other nodes
4. Each node votes for at most one candidate per term
5. First candidate to receive **quorum (majority)** votes becomes leader

**Terms:** Logical clocks. If node A receives a message from term 5 while it's in term 4, it immediately knows it's out of date. It updates to term 5 and becomes a follower. This prevents old leaders from issuing stale commands after a new election.

### Quorum Math

A quorum is a majority: `floor(n/2) + 1`

**Why majority?** Any two majorities of a set overlap by at least one node. This makes it physically impossible for two candidates to both win an election in the same term.

**Why odd numbers?**
- 3 nodes: quorum = 2. Survives 1 failure. (3-2=1)
- 4 nodes: quorum = 3. Survives 1 failure. (4-3=1)
- Same fault tolerance at higher cost and slower writes. **Even numbers are a waste of money.**
- 5 nodes: quorum = 3. Survives 2 failures.
- 7 nodes: quorum = 4. Survives 3 failures.

Most companies stop at 5. Beyond that, the latency tax (leader must wait for more ACKs) outweighs the fault tolerance benefit.

### Log Replication — The Golden Path

When a write arrives at the leader:

1. Leader writes entry to its own log as **uncommitted** (just a proposal)
2. Leader sends `AppendEntries` to all followers: "Add this to your log"
3. Followers write to their logs and send back ACK
4. Leader waits for **quorum** ACKs (including itself)
5. Once quorum ACKs received: leader **commits** — applies to state machine, tells user "success"
6. Next heartbeat: leader tells followers "entry N is committed, apply it"

**Guarantee:** Data is only "true" once it exists on a majority of nodes. Even if the leader dies after commit, at least two nodes in a 5-node cluster have the data.

### Handling Failures

> Node one is the leader. Node one's power cable is chewed through by a billionaire's pet tiger. Node one is gone.

**Simple leader failure:** Followers' heartbeat timers expire. Randomized timeouts ensure one candidate emerges first. New leader elected in ~200ms. System healed.

**Network partition (the scary one):**

Partition splits cluster: {node1, node2} vs {node3, node4, node5}.

- **Minority side (nodes 1, 2):** Node 1 (old leader) tries to commit writes but can only get 2 ACKs. Never reaches quorum of 5. Never commits. User requests time out. System chooses **consistency over availability** — refuses to lie.

- **Majority side (nodes 3, 4, 5):** Heartbeats from node 1 stop arriving. Election held. Node 3 becomes new leader (term 3). Writes on this side reach quorum (3/5). Commits proceed normally.

**When network heals:** Node 1 receives heartbeats from node 3 (term 3 > node 1's term 2). Node 1 immediately steps down. Discards its uncommitted write. Copies the truth from node 3. **Split brain resolved perfectly by quorum math.**

### Coordination Services in the Wild

**etcd:** Raft-based key-value store. The **brain of Kubernetes** — stores state of every container and service. If etcd loses consensus, the entire Kubernetes cluster freezes.

**ZooKeeper (legacy):** Used ZAB (ZooKeeper Atomic Broadcast). Was required by Kafka for leader election. Kafka 4.0 (2025) dropped ZooKeeper entirely in favor of **KRaft** — Kafka's own internal Raft-based metadata layer.

**Google Spanner:** Each shard is a Paxos-controlled group. Sharded consensus across the entire planet. The final boss of database engineering.

### When NOT to Use Raft

Consensus is slower than single-node Postgres:
- **Network hop:** Must wait for ACKs
- **fsync required:** Log must be physically durable before ACK
- **Leader bottleneck:** All writes through one CPU

**Use Raft for metadata:** Who is the shard leader? What is the DB IP? Is maintenance mode on? Small, critical pieces of data where being wrong breaks everything.

**For everything else:** Eventually consistent patterns (chapter 8).

---

## 10. Caching
📺 [Watch on YouTube](https://www.youtube.com/watch?v=t9jtxlu7k4k)

### The Memory Hierarchy Ladder

| Level | Typical Size | Latency | Human Scale (1 cycle = 1 second) |
|---|---|---|---|
| CPU Registers | Bytes | ~0.3 ns | Instant |
| L1 Cache | 32–64 KB | ~0.5 ns | 0.5 seconds |
| L2 Cache | 256 KB–1 MB | ~4 ns | 7 seconds |
| L3 Cache | 4–32 MB | ~10 ns | 25 seconds |
| RAM | 8–512 GB | ~100 ns | 2 minutes |
| SSD | TB | ~100 µs | 4.5 hours |
| HDD | TB | ~5 ms | 2–5 months |
| Network (cross-DC) | — | ~150 ms | 2.5 years |

The gap between L1 cache and a spinning disk is **seven orders of magnitude** — a different universe, not just a performance difference.

### The 90/10 Rule (Power Law)

In almost every system ever built, 90% of requests touch only 10% of the data.
- Twitter: people read tweets from the last 10 minutes, not the 5-year archive
- E-commerce: 80% of page views hit 20 best-selling products
- Video platform: top 1% of videos = 80% of bandwidth

**This is our lucky break.** If most requests target a small subset, we can promote that subset up the memory ladder. This is why caching works.

### Locality of Reference

**Temporal locality:** Accessed recently → likely to be accessed again soon. The hot tweet example.

**Spatial locality:** If you access one byte, the neighbors are probably needed too. Why the OS reads a full 4KB page when you access 1 byte.

These two observations are the entire foundation of why caching works.

### Cache Hit Rate

```
cache_hit_rate = cache_hits / (cache_hits + cache_misses)
```

At 95% hit rate, only 5% of requests touch the disk. The rest are answered from RAM. This is why modern computing feels fast — the 90/10 rule means 95%+ hit rates are achievable in practice.

### Caching Strategies

**Cache-Aside (Lazy Loading) — Most Common**

```
user = redis.get("user:123")
if user is None:                    # cache miss
    user = db.query("SELECT ...")   # hit database
    redis.set("user:123", user, ttl=3600)  # populate cache
return user
```

- Read from cache first; on miss, read from DB and populate cache
- Cache is optional — if Redis goes down, app falls back to DB (slower but functional)
- **Weakness:** First request always misses (cold start). Risk of stale data if DB changes without invalidating cache.

**Write-Through**

Every write goes through the cache first. Cache writes to DB synchronously and confirms before returning success.

- **Strength:** Cache and DB always in sync. No stale data.
- **Weakness:** Writes are not faster — still blocked on DB. You've made reads fast but not writes.

**Write-Back (Write-Behind)**

App writes to cache only. Cache returns success immediately, marks data as "dirty." Background process flushes dirty entries to DB in batches every few seconds.

- **Strength:** Write speed limited by RAM, not disk. Millions of updates/second possible.
- **Risk:** Cache crash before flush → permanent data loss. DB never received those writes.

**Real-world example:** When you save a Word document, the OS marks it in page cache and tells Word "saved." Physical SSD write happens 30 seconds later. This is why you're supposed to safely eject a USB drive — you're giving the OS time to flush the write-back.

### Cache Invalidation — The Hard Problem

> "There are only two hard things in computer science: cache invalidation and naming things." — Phil Karlton

**The core problem:** You now have two copies of the truth. When the DB truth changes, the cache copy becomes stale.

**Tool 1 — TTL (Time to Live):**
Every cache entry has an expiration timer. After 60 seconds, throw it out. Simple, predictable.

Trade-off: data can be wrong for up to TTL seconds. Set TTL based on how stale the business can tolerate.
- Social media like count: 60s TTL totally fine
- Bank balance: No caching of actual balance (or TTL of 0)

**Tool 2 — Eviction Policies:**
When cache fills up, what to remove?

- **LRU (Least Recently Used):** Evict what hasn't been accessed the longest. Aligns perfectly with temporal locality. Default for Redis, browser caches.
- **LFU (Least Frequently Used):** Evict what is accessed least often overall. Better for skewed distributions but more complex.

**Tool 3 — Manual Invalidation:**
When DB updates, send a `DELETE user:123` command to cache. Cache immediately discards the stale entry.

- Works well in single-server setup
- **Distributed nightmare:** DB update succeeds, network message to cache lost → cache permanently stale until TTL. 10 cache servers, only 6 reached → 4 permanently wrong.

**Every strategy has failure modes.** No perfect answer — just the answer that fits your system's tolerance for staleness.

### Thundering Herd

**Scenario:**
- DB can handle 1,000 queries/sec
- App gets 10,000 queries/sec; cache absorbs 95% → only 500 reach DB
- Cache server crashes → all 10,000 queries hit DB simultaneously
- DB rated for 1,000 crashes under 10,000
- DB restarts → cache is still empty → 10,000 again → DB crashes again
- Loop. Production down for hours.

**Fix — Cache Warming:**
Before sending real traffic to a server, pre-populate the cache with the most common 10% of data. Build the shield before opening the gate.

### Cache Penetration Attack

**Scenario:** Attacker sends requests for keys that don't exist (`GET user:99999999` repeatedly). Cache misses on every request. Every request hits the DB. Cache offers zero protection.

**Fix — Bloom Filter:**
A probabilistic data structure that answers in nanoseconds: "Is this key definitely NOT in the system?" If the Bloom filter says definitely not, reject immediately — DB never queried.

### Caching is Fractal

Caching exists at every layer of the stack:
- **Browser:** CSS/JS files cached locally (HTTP Cache-Control headers)
- **CDN edge:** Geographic caches. Netflix serves videos from cache boxes inside local ISPs. Amsterdam stream comes from a server a few km away, not California.
- **Application layer:** Redis/Memcached absorbing repeated DB queries
- **Database buffer pool:** Postgres/MySQL maintain in-RAM caches of recently-read pages
- **OS page cache:** Kernel keeps recently-accessed files in unused RAM

**Architect's job:** Find the bottleneck in the request path, then decide at which layer to cache.

- User in Sydney, server in New York → speed-of-light problem → Redis in New York doesn't help → need a CDN edge node in Sydney
- User and server in same city, 2-second queries → disk I/O problem → Redis in front of DB helps

### Caching Principles

1. **Don't add a cache before you need one.** A well-indexed Postgres on modern hardware handles thousands of req/s. Cache adds invalidation bugs for zero benefit at small scale.
2. **Trust the 90/10 rule.** You don't need to cache everything. Cache the hot 10% and you've solved the problem.
3. **Plan for invalidation before you build the cache.** If you're caching it, you need a documented strategy for what happens when the truth changes.
4. **Protect the database.** Your cache is a shield. Know how much the DB behind it can take. Warm the cache before sending traffic.

---

## 11. Asynchronous Systems — Kafka vs RabbitMQ vs SQS
📺 [Watch on YouTube](https://www.youtube.com/watch?v=mQf7RtBuiaY)

### Temporal Coupling — The Enemy of Scale

> When was the last time you uploaded a profile picture and the website showed you a loading spinner for 30 seconds? You stared at it, started refreshing, then just left — assuming it was broken. That experience wasn't just bad UX. It was a symptom. Somewhere on a server, a thread was sitting there blocked, holding a connection open, consuming memory and CPU — waiting for a chain of side effects to finish: resize the image, send the welcome email, update the search index, notify the shipping department. All of it in sequence. While you just wait.

**Synchronous (request-response) = phone call:** Both parties must be available at the same time. If the called party is slow or crashes, the caller is blocked. The chain stalls.

**Asynchronous (event-driven) = text message:** Sender drops a message and continues immediately. Receiver processes at their own pace.

**The user experience problem:** Synchronous signup chain — save user + resize avatar + send welcome email + update search index + notify shipping — blocks the user for 30 seconds if any link is slow. One thread per user, holding a connection, consuming resources, waiting.

**The fix:** Service publishes a fact ("user signed up") into a message queue and immediately returns success to the user. Background workers consume at their own pace.

### Load Leveling

The queue acts as a **shock absorber** between producers and consumers.

Normal day: producer generates 10 events/sec, consumer processes 10/sec. Queue empty.
Reddit hug of death: producer generates 1,000 events/sec. In sync world: 990 users see errors. In async world: 990 messages queue safely. Every user gets instant success response. Consumer is behind (welcome email arrives 10 minutes late instead of 10 seconds), but **nothing crashed and nothing was lost**.

**Trade:** real-time latency for system stability. For most workloads, a profoundly good trade.

### Task Queues vs Message Streams

| | Task Queue (SQS, RabbitMQ, Celery) | Message Stream (Kafka, AWS Kinesis) |
|---|---|---|
| **Mental model** | Post office | Infinite scroll of paper |
| **Message lifetime** | Deleted after processing | Persisted, never deleted by consumers |
| **Consumer model** | One message → exactly one consumer | Multiple independent consumers, each with own offset |
| **Semantics** | "Do this job exactly once" | "This event happened — observe it" |
| **Replayability** | No | Yes — move offset backward to replay history |
| **Use for** | Image resizing, email sending, discrete work units | Analytics, audit logs, event sourcing, multiple consumers |

**Decision rule:** Discrete job that needs to happen once → task queue. Fire hose of events that multiple systems need to observe, or that you might need to replay → stream.

### Kafka Internals — Why It's Fast

Kafka's performance comes from understanding hardware physics, not magic networking:

**1. Sequential I/O:**
Every write is an append to the end of the log. No random seeks. Even a spinning HDD sustains hundreds of MB/s of sequential throughput. Kafka sidesteps random I/O entirely.

**2. Zero-Copy Transfer (sendfile syscall):**
Traditional path: disk → kernel space → application memory → kernel space → network card. Kafka uses `sendfile`: disk → kernel page cache → network card. The Kafka broker's own process is largely bypassed. Data never lands in application memory.

**3. Partitions — Horizontal Scaling:**
A topic is split into multiple partitions, each on different physical machines. 50 partitions = 50 brokers = 50 consumer instances reading simultaneously.

LinkedIn (Kafka's creator) processes 7 trillion messages/day with this architecture.

**Ordering caveat:** Kafka guarantees ordering only within a partition. Use a **partition key** (e.g., user_id) to ensure all events for a given user go to the same partition.

### Backpressure

What happens when producers generate more than consumers can handle?

**Three strategies:**

1. **Drop messages (lossy queue):** When queue is full, new messages are discarded. Acceptable for logs, metrics, analytics. Never for financial transactions.

2. **Block:** Producer thread waits when queue is full. **Trap:** You've turned your beautiful async system back into a synchronous one. The caller thread is blocked again. You're back where you started.

3. **Dynamic scaling:** Auto-scale consumers when queue depth rises. AWS Lambda, Kubernetes HPA. **Trap:** If 50 new consumer instances all hammer the DB simultaneously, you've moved the bottleneck from the queue to the DB.

**Dead Letter Queue (DLQ):** When a message fails its final retry, move it to the DLQ (quarantine). Main system keeps running. Engineers inspect DLQ later: bug in code? fix and replay. User's card expired? Send email. DLQ is garbage collection for business logic.

### Idempotency — Non-Optional

Distributed systems are unreliable. A consumer can crash after doing work but before ACKing the queue. The queue resends the message. Consumer processes it again.

**At-least-once delivery** is the default guarantee of production queues (SQS, Kafka). Your consumers will receive the same message more than once. Build for it.

**Idempotent operation:** Produces the same result whether executed once or a hundred times. No additional side effects beyond the first execution.

**Idempotency key pattern:**
```
1. Every message carries a unique ID (message_id)
2. Consumer checks: "Have I processed message_id already?"
   - YES → send ACK, return. Do nothing.
   - NO  → do the work → record message_id as processed → send ACK
```

Without idempotency keys + at-least-once delivery = a corruption engine. Double charges, duplicate emails, phantom records.

### The Transactional Outbox Pattern

**The dual-write problem:**
```python
# This looks fine. It is not fine.
db.save(user)          # Step 1: succeeds
queue.publish(event)   # Step 2: server crashes before this runs
```

Result: user exists in DB, but downstream systems (email, analytics, search) never know about them. Silent inconsistency.

Reversing the order has the opposite problem (event published for a user that doesn't exist in DB).

**Solution — Transactional Outbox:**
```sql
-- Single atomic transaction
BEGIN;
  INSERT INTO users ...;
  INSERT INTO outbox (event_type, payload) VALUES ('user_signed_up', ...);
COMMIT;
-- Either both succeed or neither succeeds. ACID guarantees.
```

A separate background process (relay/CDC connector) reads the outbox table and publishes to the actual message queue. You've bridged the gap between DB truth and messaging with full ACID guarantees.

### When to Use Async

**Use async when:**
- Tasks take >200ms (image processing, PDF generation, video transcoding)
- Third-party API calls where you don't need the result immediately (emails, webhooks)
- High-volume data streams with tolerable latency (logs, analytics, audit trails)
- Decoupling services where teams need to evolve independently

**Don't use async when:**
- You can solve it synchronously in <100–200ms — just do that
- Premature async is its own form of over-engineering

---

## 12. The Mathematics of the Second Attempt
📺 [Watch on YouTube](https://www.youtube.com/watch?v=s5HWkMyRRcA)

### Core Mindset Shift

**Junior engineers focus on MTBF** (Mean Time Between Failures). Try to make the system never fail.  
**Senior engineers focus on MTTR** (Mean Time to Recovery). Accept that failure is inevitable. Spend time making the system recover faster.

```
System fails once/year but takes 24 hours to fix → bad system
System fails daily but heals itself in 100ms via circuit breakers → world-class system
```

Failure is not an exception. **Failure is a feature of the system.** A system that assumes success is a glass house. A senior architect builds a system that fails gracefully and heals itself.

### The Retry Storm Problem

> Imagine a service at 95% CPU, barely hanging on. A small spike hits and now it's failing 10% of requests. If all your clients have simple immediate retries, what happens? The 10% of failed requests just doubled the load on an already dying server. More failures → more retries → more failures. Within seconds, your 10% failure rate becomes a 100% outage. You have, with your very polite-sounding retry logic, basically finished off your own server.

**Naive retry:** API returns 500 → retry immediately.

**What actually happens at scale:** Service at 95% CPU. 10% of requests failing. All clients retry immediately → load increases → more failures → more retries → feedback loop. 10% failure rate becomes 100% outage in seconds.

Retries don't just fail to help — they can **actively delay recovery** by keeping load high on a struggling service.

### Exponential Backoff

Don't retry immediately. Wait. Wait longer each time.

```
Attempt 1 fails → wait 2s
Attempt 2 fails → wait 4s
Attempt 3 fails → wait 8s
Attempt 4 fails → wait 16s
...
Cap at 30-60 seconds (2^10 ≈ 1,000s = 17 minutes uncapped)
```

By backing off, you give the downstream service room to breathe. You allow engineers time to fix the problem. You are a good citizen of the network.

**But exponential backoff alone is not enough.**

### Jitter — Randomness as a Stability Mechanism

**The thundering herd problem with pure exponential backoff:**

1,000 clients all fail at t=0. All have identical 2-second backoff. At t=2.000s, all 1,000 hit the recovering server simultaneously. Server crashes again. Loop.

You did everything right (added backoff) but clients are still synchronized — acting like a coordinated army.

**Solution — Jitter:** Add random variance to the sleep time.

```python
sleep_time = base_delay * (2 ** attempt) + random.uniform(0, base_delay)
# Instead of all sleeping exactly 2s, some sleep 1.8s, 2.1s, 2.4s...
```

This smears requests across time. Instead of a spike of 1,000 requests in one millisecond, the server sees a gentle rain of requests over a full second.

**AWS empirical finding:** Jittered backoff consistently outperforms non-jittered. No exceptions found in testing. Non-jittered exponential backoff is "the clear loser" — more work, more time than any jittered approach.

**If you write a retry loop without `random` in your sleep timer, you're doing it wrong.**

### Idempotency Keys — The Foundation of Retry Safety

A retry-able payment:

```
User clicks "buy"
→ Server calls Stripe: "Charge $100"
→ Stripe charges, sends success
→ Network drops the response packet
→ Server times out, assumes failure
→ Server retries: "Charge $100" again
→ Stripe charges again
→ User charged $200
```

The charge operation was not idempotent.

**Fix:**
```
1. Generate unique ID: txn-abc-123
2. Send: "Charge $100" + idempotency_key=txn-abc-123
3. Stripe checks: "Seen txn-abc-123?" → No → Charges, records txn-abc-123
4. Network fails, retry with same key
5. Stripe checks: "Seen txn-abc-123?" → Yes → Returns cached success. No double charge.
```

**Idempotency key implementation:**
1. Generate a UUID on the client side before the request
2. Send it with every write operation
3. Server stores `(idempotency_key → response)` in DB before returning
4. On duplicate request: return cached response without re-executing

**This is a precondition for safe retry logic.** If your operations aren't idempotent, you cannot safely retry, and if you can't retry, you can't survive network failures.

### Circuit Breaker Pattern

**Problem:** A dependency is completely dead. Even with backoff and jitter, you're still holding threads open waiting for timeouts. Wasting your own resources being polite to a corpse.

**Solution:** Circuit breaker (named after the electrical component in your house).

| State | Condition | Behavior |
|---|---|---|
| **Closed** | Normal operation | Requests flow through |
| **Open** | Failure rate exceeds threshold (e.g., 50% in last 60s) | Immediately returns error. Doesn't attempt the call. Fails fast. |
| **Half-Open** | After timeout (e.g., 30s) | Lets one "scout" request through. Success → close circuit. Failure → reopen. |

**Benefits:**
- Users get immediate response instead of waiting 30s for a timeout
- Protects your system from cascading failure caused by a dead dependency
- System bends and snaps back rather than staying broken

### Dead Letter Queue (DLQ)

**Scenario:** A message has failed its maximum retry count. You can't delete it (might be a $10k order) and you can't keep it in the main queue (blocks all healthy messages behind it like a highway accident).

**Solution:** Move to DLQ (quarantine). Main queue continues processing. Engineers investigate DLQ later:
- Bug in code → fix, replay messages
- User's credit card expired → send email
- One-time weirdness → replay manually

**DLQ = garbage collection for business logic.** No data is ever truly lost even in total failure. Dramatically underrated pattern.

### Timeouts — The Missing Piece

**Most common way distributed systems die:** A missing timeout.

Without a timeout, a thread waits forever. If the called service hangs (deadlock, just slow), your thread stays open. Another thread, another. Soon all 100 web server threads are stuck. Your server is a brick.

**Rule:** Never make a network call without a timeout. Every layer:
- Connection timeout (how long to establish connection)
- Read timeout (how long to wait for a response after connecting)
- Total request timeout (hard wall clock deadline)

**Deadline propagation (advanced):**
```
User's browser willing to wait 10s
→ Web server tells service A: "You have 9s"
→ Service A tells service B: "You have 8s"
```

Prevents **zombie processing** — service B computing a result the user abandoned 8 seconds ago. Computation happening in a vacuum.

### Graceful Degradation

> The question isn't "how do I prevent this from ever breaking?" It's: if this database goes away, what does the user see? If this API call fails, does the whole page go blank or do we just hide one small widget? Can we degrade gracefully?

Senior engineers design for what the user sees when a dependency fails:

- Recommendation service down → show popular movies list (not an error screen)
- Search service slow → show cached results (slightly stale, but functional)
- Analytics service down → log events locally, replay later (user flow unaffected)

**The ceiling of system design: invisible failure handling.** The user never knows the system is partially broken.

### The Resilience Architecture Checklist

1. **Expect failure.** Don't be surprised by a 500. Be surprised when it doesn't happen.
2. **Retry smartly.** Exponential backoff. Always add jitter. AWS empirical research: jitter always wins.
3. **Be idempotent.** Every write operation needs a key so you can retry without fear. This is the foundation of distributed trust.
4. **Trip the circuit.** Circuit breakers fail fast when a dependency is gone. Stop trying to reach a dead service.
5. **Quarantine misfits.** DLQs ensure no data is lost even in total failure.
6. **Set deadlines.** Timeouts everywhere. Propagate them down the call stack.

---

## Appendix: Cross-Cutting First Principles

### The Hierarchy of Physical Reality in Software

```
Speed of light (unchangeable)
  → Network latency is a physical floor, not a bug
    → Minimize round trips, not just latency per trip
      → CDN, edge servers, connection pooling

Physics of storage (slower as further from CPU)
  → Cache hot data at the highest appropriate layer
    → 90/10 rule means high cache hit rates are achievable
      → Caching is always a consistency trade-off

Sequential vs random I/O (sequential always faster)
  → Append-only logs (WAL, Kafka, LSM trees) beat random writes
    → B-tree for reads, LSM for writes
      → Hardware physics dictates data structure choice

Fallibility of distributed nodes
  → Plan for failure at every layer
    → Consensus (Raft) for metadata, eventual consistency for volume
      → Idempotency + backoff + circuit breakers = resilient systems
```

### Decision Cheat Sheet

| Situation | First Question to Ask | Then Ask |
|---|---|---|
| Slow system | Is it latency-bound or bandwidth-bound? | Where is the bottleneck? What am I moving it to? |
| Database choice | What are my 5 most common access patterns? | What's the join tax vs the query tax? |
| Cache design | What's my TTL tolerance? | What's my invalidation strategy? |
| Scaling | Can I delete old data? Optimize queries? Add cache? | Only then: shard |
| Distributed state | Do I need strong consistency or can I tolerate eventual? | What's the cost of being wrong for N seconds? |
| Reliability | What does the user see when each dependency fails? | What is my MTTR for each failure mode? |
| Async vs sync | Can I solve this in <100-200ms synchronously? | Yes → sync. No → async |

### The Latency Numbers Table (Absolute, for Quick Reference)

| Operation | Latency |
|---|---|
| L1 cache | 0.5 ns |
| Branch misprediction | 5 ns |
| L2 cache | 7 ns |
| Mutex lock/unlock | 25 ns |
| Main memory (RAM) | 100 ns |
| Compress 1K with Snappy | 3,000 ns (3 µs) |
| Read 1 MB sequentially from RAM | 250,000 ns (250 µs) |
| Disk seek (HDD) | 10,000,000 ns (10 ms) |
| Read 1 MB sequentially from SSD | 1,000,000 ns (1 ms) |
| Read 1 MB sequentially from HDD | 20,000,000 ns (20 ms) |
| Same-DC network round trip | 500,000 ns (0.5 ms) |
| TCP packet: California→Netherlands→California | 150,000,000 ns (150 ms) |

> _Source: Jeff Dean's original "Numbers Every Programmer Should Know," updated for modern hardware_
