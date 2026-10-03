# Tree-of-Thought (ToT)

Tree-of-Thought (ToT) is an advanced prompting architecture where a model explores multiple reasoning paths, evaluates them, and "backtracks" if a path leads to a dead end. It is the blueprint behind modern search-based agents, and RL-trained reasoning models now internalize much of it inside a single long reasoning trace.

## Table of Contents

- [The Tree vs. The Chain](#the-tree-vs-the-chain)
- [The ToT Loop: Propose, Evaluate, Search](#the-tot-loop-propose-evaluate-search)
- [Self-Correction & Backtracking](#self-correction--backtracking)
- [MCTS and Search-as-Service](#mcts-and-search-as-service)
- [Interview Questions](#interview-questions)
- [References](#references)

---

## The Tree vs. The Chain

While **Chain-of-Thought** is linear (one path), **Tree-of-Thought** allows for branching.

| Feature | Chain-of-Thought | Tree-of-Thought |
|---------|------------------|-----------------|
| **Topology** | Linear (1 path) | Branching (Multiple paths) |
| **Logic** | Sequential | Parallel + Evaluative |
| **Self-Correction**| Low (Commitment bias) | High (Backtracking) |
| **Use Case** | Math, Simple Logic | Puzzle Solving, Coding Architecture, Strategic Planning |

---

## The ToT Loop: Propose, Evaluate, Search

A ToT system consists of three modules:
1. **Thought Proposer**: Generates 3-5 potential "next steps" for a problem.
2. **State Evaluator**: Grades each step (e.g., "Good", "Maybe", "Impossible").
3. **Search Algorithm**: (BFS or DFS) to decide which branch to explore next.

```python
# The ToT logic (simplified breadth-first search with pruning)
def tree_of_thought(problem, propose, evaluate, depth=3, breadth=3, threshold=0.5):
    frontier = [[]]  # each state is the list of thoughts so far
    for _ in range(depth):
        candidates = []
        for state in frontier:
            for thought in propose(problem, state, k=breadth):
                new_state = state + [thought]
                score = evaluate(problem, new_state)
                if score >= threshold:  # below threshold: prune (backtrack)
                    candidates.append((score, new_state))
        candidates.sort(key=lambda c: c[0], reverse=True)
        frontier = [state for _, state in candidates[:breadth]]
        if not frontier:
            return None  # every branch was pruned
    return frontier[0]
```

---

## Self-Correction & Backtracking

ToT is specifically designed to overcome **Hallucination Cascades**.
In a linear chain, if the model makes a mistake in Step 1, every subsequent step is likely wrong. In ToT, the "Evaluator" (which can be a different model or a rule-based check) catches the error at Step 1 and forces the model to try a different starting point.

The evaluator is the whole game. An LLM grading its own branches inherits the same blind spots that produced the error; a **deterministic evaluator** (unit tests, a type checker, a constraint solver, a game engine) is what makes backtracking reliable.

---

## MCTS and Search-as-Service

ToT has evolved into **Monte Carlo Tree Search (MCTS)** for LLMs (for example, RAP: reasoning as planning with the LLM as a world model).
- **Search-time Compute Scaling**: Instead of one large prompt, we use many small calls to "search" for the best answer: best-of-N sampling, self-consistency voting, or full tree search guided by a verifier.
- **Internalized search**: RL-trained reasoning models (GPT-6 Astra, Claude Fable 5.1 and Opus 5.5, Gemini's Deep Think mode with parallel thinking) learn to propose, check, and backtrack inside one reasoning trace, and the effort setting controls how much of that search they do. Explicit ToT scaffolding now earns its cost mainly when you have an external verifier the model cannot run itself, or when you want independent parallel samples you can score and compare.

**The scaffold can matter as much as the model.** ARC Prize tested GPT-6 Astra on ARC-AGI-3 (September 2026): 62.7% on its minimal Standard harness at max effort ($26,098), but 99.9% on a Provider Adapter harness at high effort ($18,817) that preserves the model's reasoning state between requests and uses compaction. Same model and test set: the harness that kept the model's own reasoning state won by 37 points, at a lower effort setting and a lower bill.

---

## Interview Questions

### Q: When is ToT significantly better than simple CoT?

**Strong answer:**
ToT is superior when the problem has a "large search space" and requires "global consistency." For example, in a complex software refactor, a single Chain-of-Thought might start well but hit a constraint conflict 10 steps later. With ToT, the model can propose 3 different refactoring patterns, evaluate the impact of each on the codebase, and discard patterns that lead to circular dependencies before it writes any code. It pays off most when each branch can be checked by something objective, such as the test suite or the compiler.

### Q: What is the main drawback of Tree-of-Thought in a consumer-facing app?

**Strong answer:**
The primary drawback is **Exponential Cost and Latency**. Exploring 3 branches to a depth of 5 means a proposal and an evaluation per branch per level, so 30 or more LLM calls even with aggressive pruning. In a consumer app, this could result in a 30-second delay and a $0.50 cost for a single query. The standard mitigation is a "Hybrid Model": use ToT for high-stakes offline tasks (like generating golden datasets or security audits) and distill those results into a fast, linear model for real-time interaction.

### Q: Do you still need explicit ToT when the model is already a reasoning model?

**Strong answer:**
Usually not for the search itself: a reasoning model at higher effort already explores and backtracks internally, and one call at `high` effort is simpler and often cheaper than 30 orchestrated calls. I still build explicit search in two cases. First, when an external verifier exists that the model cannot run, such as a proprietary test harness or a solver, because the verifier's signal beats the model's self-assessment. Second, when I need diversity and auditability: independent samples that I can score, compare, and log. The cost check is per solved task, not per call.

---

## References
- Yao et al. "Tree of Thoughts: Deliberate Problem Solving with Large Language Models" (2023)
- Hao et al. "Reasoning with Language Model is Planning with World Model" (RAP, 2023)
- Wang et al. "Self-Consistency Improves Chain of Thought Reasoning in Language Models" (2023)
- Silver et al. "Mastering the Game of Go without Human Knowledge" (MCTS inspiration)
- [ARC Prize. GPT-6 Astra on ARC-AGI-3 (September 2026)](https://arcprize.org/blog/astra)

---

*Next: [Context Engineering](05-context-engineering.md)*
