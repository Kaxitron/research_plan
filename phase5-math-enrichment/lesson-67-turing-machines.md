# Lesson 67: Turing Machines, Decidability, and the Halting Problem

[← Interpretability — SLT](../phase4-machine-learning/lesson-66-interp-slt.md) | [Back to TOC](../README.md) | [Next: Computational Complexity →](lesson-68-computational-complexity.md)

---

> **Why this lesson exists:** Before you can ask "will this AI system behave safely?", you need to know which questions about computer programs are even *answerable in principle*. The theory of computation draws hard lines around what's decidable, and the answers are sobering. You cannot, in general, determine what a program will do. This has direct implications for alignment: certain verification goals are provably impossible in their strongest forms, and understanding exactly where those boundaries lie tells you which approaches to alignment can work and which are doomed.

## 🎯 Core Concepts

### Turing Machines — The Mathematical Definition of "Computer"

- **A Turing machine** is an abstract model of computation: a tape (memory), a head (reads/writes), a state register, and a transition function. Despite its simplicity, it can compute anything any real computer can compute — this is the Church-Turing thesis.
- **Church-Turing thesis:** anything "computable" (in the intuitive sense) is computable by a Turing machine. This isn't a theorem — it's a definition that every proposed alternative model of computation has confirmed.
- **Universal Turing machines** can simulate any other TM. A UTM takes as input a description of another machine and its input, then simulates it. This is the mathematical essence of a general-purpose computer — and of a general-purpose AI: a system that can learn to emulate any computable function.
- **Why this matters for AI:** a neural network of sufficient size is a universal function approximator; a Turing machine of sufficient tape length is a universal computer. The analogy is precise and instructive.

### The Halting Problem — The First Impossibility

- **The question:** given a Turing machine M and input x, does M eventually halt (produce an output) or run forever?
- **The answer (Turing, 1936):** NO algorithm can decide this for all M and x. The halting problem is **undecidable**.
- **The proof (by contradiction):** assume a halting decider H(M,x) exists. Construct a machine D that runs H(D,D) and does the opposite: halts if H says it loops, loops if H says it halts. Then D(D) creates a contradiction regardless of what H outputs. D can't halt AND not halt. So H can't exist.
- **The diagonal argument:** this proof is structurally identical to Cantor's proof that the reals are uncountable, and to Gödel's incompleteness theorem. The pattern — self-reference leading to contradiction — is the deepest structural insight in mathematical logic.

### Rice's Theorem — Everything Interesting Is Undecidable

- **Rice's theorem:** ANY non-trivial semantic property of programs is undecidable. If you want to know whether a program "computes a function with property P" (for any interesting P), no algorithm can decide this in general.
- **Examples of undecidable properties:** "Does this program always return a positive number?" "Does this program ever access unauthorized data?" "Does this AI system ever output harmful content?" "Is this AI system deceptively aligned?"
- **The critical caveat:** Rice's theorem is about *general* verification — deciding the property for ALL programs. You can still verify specific programs using techniques that don't work on all programs. Formal verification, type systems, and mathematical proofs work for specific cases. They just can't be universal.
- **For alignment:** you cannot build a general-purpose "alignment verifier" that takes any AI system as input and determines whether it's aligned. But you CAN verify alignment of specific systems using specific techniques — the art is finding techniques that work for the systems you care about.

### Decidability Landscape — What Can and Can't Be Decided

- **Decidable:** finitely many cases to check, or a clever algorithm exists. "Is this string a valid Python program?" (syntactic property — decidable). "Does this finite-state machine accept this string?" (decidable). "Is this propositional logic formula satisfiable?" (decidable, but exponentially slow).
- **Semi-decidable (recognizable):** you can confirm "yes" answers but might loop forever on "no" answers. "Does this program halt?" is semi-decidable — just run it and see if it stops. If it does, you know. If it hasn't yet... maybe it's about to, or maybe it runs forever.
- **Co-semi-decidable:** you can confirm "no" but not always "yes."
- **Undecidable:** neither semi-decidable nor co-semi-decidable. Many properties of interest fall here.

## 📺 Watch — Primary

1. **Computerphile — "Halting Problem" (with Tom Scott)**
   - *Accessible explanation of the proof with good diagrams.*
2. **Undefined Behavior — "Turing Machines Explained"**
   - *Visual walkthrough of how TMs work mechanically.*

## 📖 Read — Primary

- **"Introduction to the Theory of Computation" by Sipser** — Chapters 3–5
  - *The standard textbook. Sipser is exceptionally clear.*
- **Scott Aaronson — "Who Can Name the Bigger Number?"**
  - https://www.scottaaronson.com/writings/bignumbers.html
  - *Fun essay connecting computability to very large numbers.*

