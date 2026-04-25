# FocoFlow: Core Concepts Explained

This document explains key computer science concepts used in FocoFlow, written for someone learning systems programming and ML engineering.

---

## Table of Contents
1. [Concurrency & Lock-Free Programming](#concurrency--lock-free-programming)
2. [Memory & Cache Optimization](#memory--cache-optimization)
3. [State Machines & Finite Automata](#state-machines--finite-automata)
4. [Machine Learning Concepts](#machine-learning-concepts)
5. [System Design Patterns](#system-design-patterns)

---

## Concurrency & Lock-Free Programming

### The Problem: Shared State

When multiple threads access the same data, we have a **data race**:

```cpp
// Shared counter (BAD - data race!)
int counter = 0;

// Thread 1                  // Thread 2
counter++;                   counter++;

// What value is counter?
// Expected: 2
// Actual: Could be 1 or 2! (race condition)
```

**Why?** `counter++` isn't atomic—it's three operations:
1. Read counter (let's say 0)
2. Add 1 (result: 1)
3. Write back (counter = 1)

If both threads read 0 before either writes, both write 1. Result: counter=1 (lost update!).

### Solution 1: Mutex (Lock-Based)

```cpp
std::mutex mtx;
int counter = 0;

// Thread 1
mtx.lock();
counter++;
mtx.unlock();

// Thread 2
mtx.lock();
counter++;
mtx.unlock();

// Result: Always 2 ✓
```

**How it works:**
- `lock()` blocks until mutex is available
- Only one thread can hold lock at a time
- `unlock()` releases lock for next thread

**Cost:** 10-50 microseconds per lock/unlock (syscall overhead, context switch)

### Solution 2: Atomic Operations (Lock-Free)

```cpp
std::atomic<int> counter{0};

// Thread 1
counter++;

// Thread 2
counter++;

// Result: Always 2 ✓
```

**How it works:**
- `counter++` is compiled to atomic CPU instruction (e.g., `LOCK INC` on x86)
- CPU guarantees operation is indivisible
- No syscall, no context switch

**Cost:** 10-100 nanoseconds (100-500x faster than mutex!)

### Memory Ordering: The Subtle Part

Problem: CPUs reorder instructions for performance. This breaks correctness in lock-free code.

**Example:**

```cpp
// Thread 1 (Producer)
data = 42;           // Write A
ready = true;        // Write B

// Thread 2 (Consumer)
if (ready) {         // Read B
    print(data);     // Read A - expects 42
}
```

**Without memory ordering:**
- CPU might execute B before A (reorder for efficiency)
- Thread 2 sees `ready=true` but `data=0` (stale value)
- Prints 0 instead of 42!

**With memory ordering:**

```cpp
// Thread 1 (Producer)
data = 42;
ready.store(true, std::memory_order_release);  // Barrier: A happens-before B

// Thread 2 (Consumer)
if (ready.load(std::memory_order_acquire)) {   // Barrier: B happens-before A read
    print(data);  // Guaranteed to see data=42 ✓
}
```

**Memory orderings:**

| Ordering | When to Use | Cost |
|----------|-------------|------|
| `relaxed` | No synchronization needed (counters, flags) | Fastest |
| `acquire` | Reading data produced by another thread | Medium |
| `release` | Publishing data for another thread | Medium |
| `seq_cst` | Full ordering (default, rarely needed) | Slowest |

**Rule of thumb:**
- **Producer:** `store(..., release)` when publishing data
- **Consumer:** `load(..., acquire)` when reading data
- **Both:** `relaxed` for private data or statistics

---

## Memory & Cache Optimization

### The Memory Hierarchy

```
Distance from CPU    Size      Latency    Bandwidth
────────────────────────────────────────────────────
CPU Registers        64 bytes  0 cycles   ∞
L1 Cache            32 KB      1 cycle    ~1 TB/s
L2 Cache           256 KB      4 cycles   ~400 GB/s
L3 Cache            8 MB      12 cycles   ~200 GB/s
RAM                16 GB     ~100 cycles  ~50 GB/s
SSD               512 GB     ~50,000     ~3 GB/s
────────────────────────────────────────────────────
```

**Key insight:** Cache is 100x faster than RAM. Keep data in cache!

### Cache Lines: The Fundamental Unit

CPUs don't read individual bytes—they read **cache lines** (64 bytes on x86-64).

```
RAM:
[0x1000] [0x1008] [0x1010] [0x1018] ... [0x1038]  ← 64 bytes

When you read address 0x1000, CPU loads ALL 64 bytes into cache.
Reading 0x1008 next? Already in cache (fast!).
Reading 0x1040? Different cache line (slow, fetch from RAM).
```

**Lesson:** Keep related data close together (within 64 bytes).

### False Sharing: The Silent Killer

Problem: Two threads write to different variables on the same cache line.

```cpp
struct Bad {
    int producer_counter;  // Thread 1 writes here
    int consumer_counter;  // Thread 2 writes here
} bad;  // Both in same cache line!

// Thread 1
bad.producer_counter++;  // Writes cache line → invalidates Thread 2's cache

// Thread 2
bad.consumer_counter++;  // Cache miss! Must reload from Thread 1
```

**Result:** 10x slowdown due to cache thrashing (ping-pong effect).

**Solution:** Separate cache lines with padding.

```cpp
struct Good {
    alignas(64) int producer_counter;  // Cache line 1
    alignas(64) int consumer_counter;  // Cache line 2
} good;

// Now threads don't interfere!
```

This is why our ring buffer uses `alignas(64)` for `head_` and `tail_`.

### Struct Packing: Minimizing Size

Compilers add **padding** to align fields on natural boundaries.

```cpp
// Without packing (compiler adds padding)
struct Bad {
    uint8_t a;   // 1 byte
    // [3 bytes padding]
    uint32_t b;  // 4 bytes (must align to 4-byte boundary)
};
sizeof(Bad) = 8 bytes (50% wasted!)

// With packing (no padding)
struct Good {
    uint8_t a;   // 1 byte
    uint32_t b;  // 4 bytes (no padding)
} __attribute__((packed));
sizeof(Good) = 5 bytes ✓
```

**Trade-off:** Packed structs are slower to read (unaligned access). Use only when size matters (e.g., network protocols, file formats).

---

## State Machines & Finite Automata

A **state machine** is a model where:
- System is in one **state** at a time
- **Events** cause **transitions** between states
- Each transition is explicit and defined

### Example: Traffic Light

```
States: [RED, YELLOW, GREEN]
Events: [timer_expired]

Transitions:
RED + timer_expired → GREEN
GREEN + timer_expired → YELLOW
YELLOW + timer_expired → RED
```

**Why use state machines?**

1. **Predictable:** Every state has defined behavior
2. **Testable:** Test each transition independently
3. **Debuggable:** Log state changes to trace bugs
4. **Maintainable:** Adding states doesn't break existing code

### Example: Focus Session Lifecycle

```cpp
enum class SessionState {
    IDLE,        // No session active
    ACTIVE,      // Timer running
    PAUSED,      // User paused
    COMPLETED    // Finished
};

class FocusSession {
    SessionState state = SessionState::IDLE;
    
    void start() {
        if (state == SessionState::IDLE) {
            state = SessionState::ACTIVE;
            // Start timer...
        } else {
            throw InvalidStateError("Cannot start from " + state);
        }
    }
    
    void pause() {
        if (state == SessionState::ACTIVE) {
            state = SessionState::PAUSED;
            // Pause timer...
        } else {
            throw InvalidStateError("Can only pause ACTIVE session");
        }
    }
    
    void resume() {
        if (state == SessionState::PAUSED) {
            state = SessionState::ACTIVE;
            // Resume timer...
        } else {
            throw InvalidStateError("Can only resume PAUSED session");
        }
    }
    
    void complete() {
        if (state == SessionState::ACTIVE) {
            state = SessionState::COMPLETED;
            // Save stats...
        } else {
            throw InvalidStateError("Can only complete ACTIVE session");
        }
    }
};
```

**Benefits:**
- Clear which operations are valid in each state
- Impossible to get into "weird" states (e.g., pause a completed session)
- Easy to extend (add CANCELLED state without breaking existing code)

---

## Machine Learning Concepts

### Supervised Learning: Learning from Examples

**Goal:** Learn a function `f(x) = y` from labeled examples.

**Example: Focus Prediction**

```
Training Data:
Input (features)                        Output (label)
────────────────────────────────────────────────────
[typing_speed=4.2, switches=1, ...]  →  FOCUSED
[typing_speed=2.1, switches=5, ...]  →  DISTRACTED
[typing_speed=3.8, switches=2, ...]  →  FOCUSED
...
```

**Training:** Model finds patterns that map inputs to outputs.

```python
model.fit(X_train, y_train)
# Model learns: "High typing speed + few switches = FOCUSED"
#               "Low typing speed + many switches = DISTRACTED"
```

**Inference:** Predict label for new data.

```python
new_features = [typing_speed=1.5, switches=6, ...]
prediction = model.predict(new_features)
# Result: DISTRACTED (matches training pattern)
```

### Feature Engineering: The Art of ML

**Raw data is rarely useful directly.** We must extract **features** (informative signals).

**Bad features:**
```python
features = {
    'total_keystrokes': 15000,  # Lifetime count, not current state
    'app_name': 'chrome.exe'     # String, model can't use directly
}
```

**Good features:**
```python
features = {
    'keystroke_rate_30s': 3.5,         # Recent activity (localized)
    'keystroke_variance_30s': 0.12,    # Consistency (low = steady)
    'context_switches_30s': 2,         # Stability (few = focused)
    'time_in_current_app': 45,         # Commitment (longer = focused)
    'is_ide': 1,                       # Categorical → binary encoding
    'hour_of_day': 14                  # Temporal pattern (circadian)
}
```

**Why these are good:**
1. **Localized:** 30s windows capture current state
2. **Numeric:** Model can compute with them
3. **Discriminative:** Separate focused from distracted
4. **Interpretable:** We understand why they matter

### Time Series Prediction: Forecasting the Future

**Problem:** Predict future events based on past sequence.

**Traditional ML (XGBoost):** Sees aggregated features
```
Input: [avg_speed=3.2, avg_switches=1.5]
Output: focus_score=75
```

**Sequential ML (LSTM):** Sees full history
```
Input: [(key, t=0), (key, t=0.2), (mouse, t=1.3), (switch, t=5.0), ...]
Output: focus_score=75
```

**LSTM (Long Short-Term Memory):**
- Neural network architecture designed for sequences
- Maintains "memory" of past events in hidden state
- Can learn patterns like "rapid typing → pause → switch = distraction sequence"

**When to use LSTM over XGBoost?**
- When **temporal patterns** matter (order of events)
- When you have **sufficient data** (LSTMs need more training samples)
- When you can afford **higher latency** (LSTM inference is slower)

**Our approach:**
- **Phase 1 (MVP):** XGBoost (faster, simpler, interpretable)
- **Phase 2:** LSTM (better accuracy, captures sequences)

---

## System Design Patterns

### Layered Architecture

**Principle:** Separate system into layers, each with a specific responsibility.

```
┌─────────────────────────────────────┐
│   Layer 4: Presentation (React)    │ ← User interface
├─────────────────────────────────────┤
│   Layer 3: Application (Spring)    │ ← Business logic
├─────────────────────────────────────┤
│   Layer 2: ML Service (Python)     │ ← Predictions
├─────────────────────────────────────┤
│   Layer 1: Event Capture (C++)     │ ← OS integration
└─────────────────────────────────────┘
```

**Rules:**
- Layer N can only call Layer N-1 (downward)
- Layer N exposes interface (API) to Layer N+1
- Layers are **loosely coupled** (can swap implementations)

**Example:** We can replace React with Vue without touching C++ code.

### Event-Driven Architecture

**Principle:** Components communicate via events (messages), not direct calls.

**Traditional (Tight Coupling):**
```cpp
// C++ directly calls Python function
python_service.process_event(event);  // Requires linking Python!
```

**Event-Driven (Loose Coupling):**
```cpp
// C++ publishes event, doesn't know who consumes it
event_bus.publish(event);  // Zero coupling

// Python subscribes to events
event_bus.subscribe([](Event e) {
    process_event(e);
});
```

**Benefits:**
- **Decoupling:** C++ doesn't depend on Python (can run independently)
- **Scalability:** Add more consumers without changing producer
- **Resilience:** If Python crashes, C++ keeps running

### CQRS (Command Query Responsibility Segregation)

**Principle:** Separate read operations (queries) from write operations (commands).

**Traditional:**
```
Database ← App writes AND reads from same schema
```

**CQRS:**
```
Write Model: Optimized for fast writes (append-only event log)
Read Model: Optimized for fast reads (pre-aggregated views)
```

**In Neural Focus:**
- **Write path:** C++ appends events to log (no reads, blazing fast)
- **Read path:** Python reads log, computes features (no writes to event log)

**Benefits:**
- Write path isn't slowed by queries
- Read path can use different data structure (e.g., aggregated features)
- Can scale independently (e.g., 1 writer, 10 readers)

### Producer-Consumer Pattern

**Problem:** Producer generates data faster than consumer can process.

**Solution: Buffer (Queue)**

```
Producer → [Queue] → Consumer

Producer: Writes to queue (fast, non-blocking)
Consumer: Reads from queue (slower, processes data)
Queue: Buffers overflow during bursts
```

**What if queue fills up?**

Option 1: **Block producer** (wait until space available)
- Pro: No data loss
- Con: Producer slows down (unacceptable for event capture!)

Option 2: **Drop data** (our choice)
- Pro: Producer never blocks (maintains low latency)
- Con: Some events lost (acceptable for statistics)

**Monitoring:** Track drop rate. If >0.1%, consumer is too slow (optimize Python code).

---

## Summary: Why These Concepts Matter

### For Neural Focus:

1. **Lock-Free Programming:** Achieve <1ms latency (100x faster than locks)
2. **Cache Optimization:** Process 10,000 events/sec without bottleneck
3. **State Machines:** Make focus session logic predictable and testable
4. **Feature Engineering:** Enable ML model to learn meaningful patterns
5. **Layered Architecture:** Change React UI without recompiling C++
6. **Event-Driven:** Python can crash/restart without affecting C++ capture
7. **CQRS:** Writes (event capture) don't block reads (feature extraction)
8. **Producer-Consumer:** Handle burst traffic (50,000 events/sec) gracefully

### For Your Learning:

These concepts apply to ANY high-performance system:
- **Game engines:** Lock-free queues for input handling
- **Trading systems:** Cache optimization for low-latency execution
- **Web backends:** Event-driven for scalability
- **ML pipelines:** Feature engineering for accuracy
- **Distributed systems:** CQRS for scale

**You're not just building a productivity tracker—you're learning to build production-grade systems.**

---

## Further Reading

**Concurrency:**
- *C++ Concurrency in Action* by Anthony Williams
- *The Art of Multiprocessor Programming* by Herlihy & Shavit

**Performance:**
- *Computer Architecture: A Quantitative Approach* by Hennessy & Patterson
- *Systems Performance* by Brendan Gregg

**ML:**
- *Hands-On Machine Learning* by Aurélien Géron
- *Deep Learning* by Goodfellow, Bengio, Courville

**System Design:**
- *Designing Data-Intensive Applications* by Martin Kleppmann
- *System Design Interview* by Alex Xu

**Practice:**
- Build. Break things. Fix them. Repeat.
- Read open-source code (Chromium, Linux kernel, PyTorch)
- Measure everything (profile, benchmark, monitor)

---

**Next:** Implement Win32 hooks and see these concepts in action!
