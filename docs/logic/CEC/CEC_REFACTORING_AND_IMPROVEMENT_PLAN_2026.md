# CEC Logic Folder - Comprehensive Refactoring and Improvement Plan 2026

**Version:** 3.0  
**Date:** 2026-02-19  
**Status:** Active Development  
**Focus:** Code Quality, Architecture, and Maintainability

---

## 📋 Table of Contents

1. [Executive Summary](#executive-summary)
2. [Current State Analysis](#current-state-analysis)
3. [Critical Issues (P0)](#critical-issues-p0)
4. [High Priority Issues (P1)](#high-priority-issues-p1)
5. [Medium Priority Issues (P2)](#medium-priority-issues-p2)
6. [Low Priority Issues (P3)](#low-priority-issues-p3)
7. [Refactoring Roadmap](#refactoring-roadmap)
8. [Success Metrics](#success-metrics)
9. [Implementation Guidelines](#implementation-guidelines)
10. [Risk Management](#risk-management)

---

## 📊 Executive Summary

### Purpose

This document provides a **comprehensive refactoring and improvement plan** for the `ipfs_datasets_py/logic/CEC/` folder, focusing on **code quality, maintainability, and architectural improvements** rather than new features.

### Current State (2026-02-19)

| Metric | Value | Assessment |
|--------|-------|------------|
| **Total LOC** | 24,286 | 🟡 Large codebase |
| **Python Files** | 57+ files | 🟢 Modular |
| **Functions** | 1,077 | 🟢 Good |
| **Classes** | 292 | 🟢 Good |
| **Test Files** | 56 files | 🟢 Excellent |
| **Test LOC** | 22,553 | 🟢 Excellent |
| **Test Coverage** | 208+ tests (Phases 7-8) | 🟢 Strong |
| **Documentation** | 20+ MD files | 🟢 Comprehensive |
| **Feature Parity** | 81% vs submodules | 🟢 Strong |
| **TODO/FIXME Comments** | 0 | 🟢 Clean |

### Key Findings

**✅ Strengths:**
- Excellent test coverage (208+ tests, 22,553 test LOC)
- Comprehensive documentation (20+ markdown files)
- Zero TODO/FIXME technical debt markers
- Strong feature parity (81% vs legacy submodules)
- Modular structure with clear separation

**🔴 Critical Issues (P0):**
1. **Giant files** requiring immediate splitting (prover_core.py: 2,927 LOC, dcec_core.py: 1,360 LOC)
2. **Duplicate code** across language parsers (German/French/Spanish ~95% identical)
3. **Missing architecture documentation** for native module

**🟡 High Priority Issues (P1):**
1. Import organization and circular dependency risks
2. Inconsistent string representation methods (40+ implementations)
3. Missing comprehensive API documentation
4. Type safety gaps (heavy use of `Any`)

### Transformation Goals

| Aspect | Before | After | Impact |
|--------|--------|-------|--------|
| **Largest File** | 2,927 LOC | <600 LOC | +80% maintainability |
| **Code Duplication** | ~40% in parsers | <5% | +35% reduction |
| **String Methods** | 40+ inconsistent | 1 mixin | DRY principle |
| **Documentation** | Fragmented | Unified | +60% clarity |
| **Type Safety** | ~60% | >90% | +30% safety |
| **Architecture Docs** | Missing | Complete | +100% onboarding |

### Timeline and Effort

**Total Effort:** 12-16 weeks (90-120 hours)

| Phase | Duration | Effort | Priority |
|-------|----------|--------|----------|
| Phase 1: File Splitting | 3-4 weeks | 25-35h | P0 |
| Phase 2: Consolidation | 2-3 weeks | 15-20h | P0 |
| Phase 3: Documentation | 2-3 weeks | 15-20h | P1 |
| Phase 4: Type Safety | 2-3 weeks | 15-25h | P1 |
| Phase 5: Architecture | 1-2 weeks | 10-15h | P1 |
| Phase 6: Polish | 2-3 weeks | 10-15h | P2 |

---

## 🔍 Current State Analysis

### Directory Structure

```
ipfs_datasets_py/logic/CEC/                    [24,286 LOC total]
│
├── native/                                    [~15,000+ LOC - Core Implementation]
│   ├── prover_core.py          (2,927 LOC) ⚠️  CRITICAL: Must split
│   ├── dcec_core.py            (1,360 LOC) ⚠️  CRITICAL: Must split
│   ├── shadow_prover.py          (714 LOC) ⚠️  High priority split
│   ├── dcec_english_grammar.py   (628 LOC) ⚠️  Split parsing/semantics
│   ├── modal_tableaux.py         (585 LOC) 🟢  Acceptable
│   ├── advanced_inference.py     (573 LOC) 🟢  Acceptable
│   ├── cec_zkp_integration.py    (551 LOC) 🟢  Acceptable
│   ├── event_calculus.py         (549 LOC) 🟢  Acceptable
│   ├── fluents.py                (520 LOC) 🟢  Acceptable
│   ├── lemma_generation.py       (501 LOC) 🟢  Acceptable
│   ├── proof_strategies.py       (458 LOC) 🟢  Good
│   └── [18 more files]           (~6,500 LOC)
│
├── nl/                                        [~2,700 LOC - Natural Language]
│   ├── german_parser.py          (636 LOC) ⚠️  DUPLICATE: Consolidate
│   ├── french_parser.py          (600 LOC) ⚠️  DUPLICATE: Consolidate
│   ├── spanish_parser.py         (578 LOC) ⚠️  DUPLICATE: Consolidate
│   ├── domain_vocabularies/
│   │   └── domain_vocab.py       (465 LOC) 🟢  Good
│   ├── base_parser.py            (364 LOC) 🟢  Good
│   └── language_detector.py      (100 LOC) 🟢  Good
│
├── provers/                                   [~2,400 LOC - Theorem Provers]
│   ├── z3_adapter.py             (546 LOC) 🟢  Acceptable
│   ├── prover_manager.py         (440 LOC) 🟢  Good
│   ├── vampire_adapter.py        (239 LOC) 🟢  Good
│   ├── e_prover_adapter.py       (150 LOC) 🟢  Good
│   └── tptp_utils.py             (200 LOC) 🟢  Good
│
├── optimization/                              [~900 LOC - Performance]
│   ├── formula_cache.py          (523 LOC) 🟢  Acceptable
│   └── profiling_utils.py        (393 LOC) 🟢  Good
│
├── Wrappers (Top Level)                       [~1,800 LOC]
│   ├── cec_framework.py          (492 LOC) 🟢  Good
│   ├── shadow_prover_wrapper.py  (541 LOC) 🟢  Acceptable
│   ├── talos_wrapper.py          (379 LOC) 🟢  Good
│   ├── eng_dcec_wrapper.py       (200 LOC) 🟢  Good
│   └── dcec_wrapper.py           (314 LOC) 🟢  Good
│
└── Legacy Submodules (Read-only)              [~10,500 LOC]
    ├── DCEC_Library/             (Python 2, 2,300 LOC)
    ├── Talos/                    (Python 2, 1,200 LOC)
    ├── Eng-DCEC/                 (GF/Lisp, 2,000+ LOC)
    └── ShadowProver/             (Java, 5,000+ LOC)
```

### File Size Distribution

| Size Range | Count | Files | Priority |
|------------|-------|-------|----------|
| **>2,000 LOC** | 1 | prover_core.py | 🔴 Critical |
| **1,000-2,000** | 1 | dcec_core.py | 🔴 Critical |
| **600-999** | 3 | shadow_prover.py, german_parser.py, dcec_english_grammar.py | 🟡 High |
| **500-599** | 9 | Various | 🟢 Acceptable |
| **<500** | 43 | Various | 🟢 Good |

### Code Metrics

```
Total Python Files:        57
Total Lines of Code:       24,286
Total Functions:           1,077 (avg 22.5 LOC/function)
Total Classes:             292 (avg 83.2 LOC/class)
Average File Size:         426 LOC
Median File Size:          ~450 LOC
Largest File:              2,927 LOC (prover_core.py)
```

### Test Coverage

```
Test Files:                56
Test LOC:                  22,553
Test/Code Ratio:           0.93 (excellent)
Recent Test Additions:     208 tests (Phases 7-8)
Test Organization:         ✅ Mirrors source structure
Coverage Estimate:         80-85% (strong)
```

### Dependencies

**External Dependencies:**
- ✅ `beartype` (optional, runtime type checking)
- ✅ `z3-solver` (optional, SMT solving)
- ✅ `vampire` (optional, FOL prover)
- ✅ `eprover` (optional, equational prover)
- ✅ `nltk` (implicit, for NL processing)

**Internal Dependencies:**
```
dcec_core.py ← Foundation for all native modules
  ├─ prover_core.py
  ├─ shadow_prover.py
  ├─ modal_tableaux.py
  ├─ temporal.py
  ├─ event_calculus.py
  └─ All NL modules
```

---

## 🔴 Critical Issues (P0)

### Issue P0-1: Giant Files Requiring Immediate Splitting

#### Problem Statement

**prover_core.py (2,927 LOC)** and **dcec_core.py (1,360 LOC)** are monolithic files that violate the Single Responsibility Principle and severely impact maintainability.

#### Detailed Analysis

**prover_core.py Breakdown:**
```python
# Current structure (2,927 LOC):
- 120+ inference rule classes (60-80 LOC each)          ~8,000 LOC conceptual
- Proof engine core logic                               ~400 LOC
- Proof caching system                                  ~300 LOC
- Proof tree generation                                 ~250 LOC
- Strategy management                                   ~200 LOC
- Utility functions                                     ~150 LOC
- Type definitions and enums                            ~100 LOC
```

**dcec_core.py Breakdown:**
```python
# Current structure (1,360 LOC):
- Type definitions (Enums, dataclasses)                 ~400 LOC
- Formula classes (Atomic, Connective, etc.)            ~500 LOC
- Operator implementations                              ~300 LOC
- Serialization/deserialization                         ~160 LOC
```

#### Proposed Refactoring

**Step 1: Split prover_core.py into Inference Rules Package**

```
native/inference_rules/                      [New package]
├── __init__.py                              Export all rules
├── base.py                                  InferenceRule ABC + utilities
├── propositional.py                         AND, OR, NOT, IMP rules (15-20 rules)
├── first_order.py                           Universal/existential (10-15 rules)
├── temporal.py                              Temporal reasoning (15-20 rules)
├── deontic.py                               Deontic logic (10-12 rules)
├── modal.py                                 Modal operators (12-15 rules)
├── cognitive.py                             Belief/knowledge/intention (10-12 rules)
└── specialized.py                           Advanced/specialized (20-25 rules)

Target: 8 files × ~350 LOC = 2,800 LOC (vs 2,927 LOC)
Improvement: Modular, testable, extensible
```

**Step 2: Split prover_core.py Core Logic**

```
native/prover/                               [New package]
├── __init__.py                              Export main Prover class
├── engine.py                                Core proof engine (400 LOC)
├── cache.py                                 Proof caching system (300 LOC)
├── tree.py                                  Proof tree generation (250 LOC)
├── strategy.py                              Strategy management (200 LOC)
└── utils.py                                 Helper functions (150 LOC)

Target: 6 files × ~200-400 LOC = ~1,300 LOC
```

**Step 3: Split dcec_core.py**

```
native/types/                                [New package]
├── __init__.py                              Export all types
├── enums.py                                 DeonticOperator, CognitiveOperator, etc.
├── terms.py                                 Variable, Term, Constant
├── formulas.py                              Formula hierarchy
├── operators.py                             Operator implementations
└── serialization.py                         To/from string conversion

Target: 6 files × ~200-300 LOC = ~1,500 LOC (vs 1,360 LOC)
```

#### Implementation Steps

1. **Week 1-2: Create package structure**
   - Create `native/inference_rules/` package
   - Create `native/prover/` package  
   - Create `native/types/` package
   - Add `__init__.py` with exports

2. **Week 2-3: Extract inference rules**
   - Extract rules to respective modules
   - Update imports in prover_core.py
   - Run tests continuously

3. **Week 3-4: Extract prover components**
   - Move cache, tree, strategy to separate files
   - Update internal imports
   - Validate all tests pass

4. **Week 4: Extract dcec_core components**
   - Move types to types/ package
   - Update all imports across codebase
   - Run full test suite

5. **Week 4: Clean up and deprecation**
   - Mark old files as deprecated
   - Add migration guides
   - Final test validation

#### Success Criteria

- ✅ No file >600 LOC
- ✅ All 208+ tests passing
- ✅ Zero import errors
- ✅ Maintainability index >75 for all new files
- ✅ Code duplication <3%

#### Expected Impact

| Metric | Before | After | Change |
|--------|--------|-------|--------|
| **Largest File** | 2,927 LOC | <600 LOC | -79% |
| **Maintainability** | ~50 | >75 | +50% |
| **Test Time** | Baseline | -10% | Faster |
| **Import Complexity** | High | Low | Clearer |

#### Risks

- **Medium:** Circular import risks during transition
- **Low:** Temporary test failures during refactor
- **Mitigation:** Incremental changes, continuous testing

---

### Issue P0-2: Duplicate Code in Language Parsers

#### Problem Statement

German, French, and Spanish parsers have **~95% identical implementations** with only vocabulary differences, resulting in **~1,814 LOC of duplication** (636 + 600 + 578 LOC).

#### Evidence

```python
# Identical structure in all 3 parsers:
class GermanParser(BaseParser):
    def __init__(self):
        self.patterns = {...}  # Only difference: German vocab

    def parse_sentence(self, text):  # Identical logic
        ...

    def extract_agents(self, text):  # Identical logic
        ...

    def extract_actions(self, text):  # Identical logic
        ...

    # 30+ identical methods with only vocabulary changes
```

#### Proposed Refactoring

**Step 1: Create Unified Multilingual Parser**

```python
# nl/multilingual_parser.py (600 LOC - single file)
class MultilingualParser(BaseParser):
    """Unified parser supporting multiple languages."""

    def __init__(self, language: str = "en"):
        self.language = language
        self.vocab = self._load_vocabulary(language)
        self.patterns = self._load_patterns(language)

    def _load_vocabulary(self, lang: str) -> Dict[str, Any]:
        """Load language-specific vocabulary from config."""
        return LANGUAGE_VOCABULARIES[lang]

    # All parsing logic once, not three times
    def parse_sentence(self, text: str) -> Formula: ...
```

**Step 2: Extract Vocabularies to Config**

```python
# nl/vocabularies/
├── __init__.py
├── english.py       (200 LOC)
├── german.py        (200 LOC)
├── french.py        (200 LOC)
└── spanish.py       (200 LOC)

# Each file:
VOCABULARY = {
    "agents": ["person", "company", ...],
    "actions": ["create", "sign", ...],
    "deontic": {
        "obligation": ["must", "shall", ...],
        "permission": ["may", "can", ...],
        ...
    },
    ...
}
```

#### Implementation Steps

1. **Week 1: Extract common logic**
   - Create `MultilingualParser` class
   - Identify truly identical methods
   - Extract to base implementation

2. **Week 1-2: Create vocabulary configs**
   - Extract German vocabulary → `vocabularies/german.py`
   - Extract French vocabulary → `vocabularies/french.py`
   - Extract Spanish vocabulary → `vocabularies/spanish.py`
   - Create loader functions

3. **Week 2: Deprecate old parsers**
   - Mark `german_parser.py` as deprecated
   - Mark `french_parser.py` as deprecated
   - Mark `spanish_parser.py` as deprecated
   - Add compatibility wrappers

4. **Week 2: Update imports**
   - Update all imports to use `MultilingualParser`
   - Update tests to use new API
   - Validate all tests pass

5. **Week 3: Remove deprecated files**
   - Delete deprecated parser files
   - Update documentation
   - Final validation

#### Success Criteria

- ✅ Reduce from 1,814 LOC → ~1,000 LOC (-45% code)
- ✅ Single parser supports all languages
- ✅ Easy to add new languages (just add vocabulary file)
- ✅ All language tests passing
- ✅ Zero regression in functionality

#### Expected Impact

| Metric | Before | After | Change |
|--------|--------|-------|--------|
| **Parser LOC** | 1,814 | ~1,000 | -45% |
| **Files** | 3 parsers | 1 parser | -67% |
| **Duplication** | 95% | <5% | -90% |
| **Add Language** | 600 LOC | 200 LOC | -67% |
| **Maintainability** | Low | High | Much better |

#### Risks

- **Low:** Language-specific edge cases
- **Low:** Test coverage gaps
- **Mitigation:** Comprehensive test suite, careful validation

---

### Issue P0-3: Missing Architecture Documentation

#### Problem Statement

The `native/` module contains 29 files with complex interdependencies, but **no architecture documentation** explaining:
- How components relate to each other
- Dependency flow and layering
- Extension points for adding features
- Design patterns used

This creates significant onboarding friction for new developers.

#### Proposed Solution

Create comprehensive architecture documentation:

```
ARCHITECTURE.md                              [New file, ~8,000 words]
├── 1. Overview
│   ├── Design principles
│   ├── Architecture layers
│   └── Component diagram
├── 2. Core Components
│   ├── dcec_core - Type system
│   ├── prover - Theorem proving engine
│   ├── inference_rules - Rule system
│   └── Dependency graph
├── 3. Subsystems
│   ├── Natural language processing
│   ├── Temporal reasoning
│   ├── Modal logic
│   └── Caching and optimization
├── 4. Extension Points
│   ├── Adding new inference rules
│   ├── Adding new operators
│   ├── Adding language support
│   └── Adding theorem provers
├── 5. Design Patterns
│   ├── Visitor pattern (formula traversal)
│   ├── Strategy pattern (proving strategies)
│   ├── Adapter pattern (external provers)
│   └── Factory pattern (formula creation)
└── 6. Developer Guides
    ├── Adding a new feature
    ├── Debugging tips
    └── Performance considerations
```

#### Implementation Steps

1. **Week 1: Document core architecture**
   - Create ARCHITECTURE.md skeleton
   - Document layer architecture
   - Create component diagrams (Mermaid)

2. **Week 1-2: Document subsystems**
   - Document prover architecture
   - Document type system
   - Document NL processing pipeline

3. **Week 2: Document extension points**
   - How to add inference rules
   - How to add operators
   - How to integrate provers

4. **Week 2: Add developer guides**
   - Quick start for contributors
   - Common patterns
   - Debugging guide

5. **Week 2-3: Review and polish**
   - Internal review
   - Add examples
   - Cross-link with existing docs

#### Success Criteria

- ✅ Architecture document >5,000 words
- ✅ Component diagrams for major subsystems
- ✅ Extension points clearly documented
- ✅ Developer onboarding time <2 hours
- ✅ Zero ambiguity in component relationships

#### Expected Impact

| Metric | Before | After | Change |
|--------|--------|-------|--------|
| **Onboarding Time** | 8-16 hours | <2 hours | -75% |
| **Architecture Clarity** | 20% | 90% | +70% |
| **Extension Time** | High | Low | Faster |
| **Bug Fix Time** | High | Lower | Faster |

---

## 🟡 High Priority Issues (P1)

### Issue P1-1: Import Organization and Circular Dependencies

#### Problem Statement

Current import structure has several issues:
1. Deep relative imports (`from ..native import`)
2. Potential circular dependency risks
3. No `__all__` exports in most modules
4. Optional dependencies (Z3, Vampire) not properly handled

#### Proposed Solution

**Step 1: Add `__all__` exports to all modules**

```python
# Every module should define __all__
__all__ = [
    "Formula",
    "AtomicFormula",
    "ConnectiveFormula",
    # ...
]
```

**Step 2: Create clear public APIs at package level**

```python
# native/__init__.py (enhanced)
"""
Native Python 3 DCEC implementation.

Public API:
    Types: Formula, Term, Variable, ...
    Operators: DeonticOperator, CognitiveOperator, ...
    Provers: Prover, ProofResult, ...
"""

# Core types
from .types import (
    Formula,
    AtomicFormula,
    # ...
)

# Provers
from .prover import Prover, ProofResult

__all__ = [
    # Types
    "Formula",
    "AtomicFormula",
    # ... (explicit list)
]
```

**Step 3: Use absolute imports throughout**

```python
# Instead of:
from ..native import Formula

# Use:
from ipfs_datasets_py.logic.CEC.native import Formula
```

**Step 4: Handle optional dependencies gracefully**

```python
# provers/__init__.py
try:
    from .z3_adapter import Z3Adapter

    HAS_Z3 = True
except ImportError:
    HAS_Z3 = False
    Z3Adapter = None

try:
    from .vampire_adapter import VampireAdapter

    HAS_VAMPIRE = True
except ImportError:
    HAS_VAMPIRE = False
    VampireAdapter = None

__all__ = [
    "HAS_Z3",
    "HAS_VAMPIRE",
]

if HAS_Z3:
    __all__.append("Z3Adapter")
if HAS_VAMPIRE:
    __all__.append("VampireAdapter")
```

#### Implementation Steps

1. **Week 1: Add `__all__` exports**
   - Add to all 57 Python files
   - Validate imports work

2. **Week 1-2: Refactor to absolute imports**
   - Replace relative imports
   - Update all modules
   - Test import paths

3. **Week 2: Handle optional dependencies**
   - Add try/except blocks
   - Add feature flags
   - Update documentation

4. **Week 2: Detect circular imports**
   - Run import checker
   - Fix any circular dependencies
   - Add CI check

#### Success Criteria

- ✅ All modules have `__all__` exports
- ✅ All imports are absolute
- ✅ Optional dependencies handled gracefully
- ✅ Zero circular import warnings
- ✅ Import time <1 second

---

### Issue P1-2: Inconsistent String Representation

#### Problem Statement

**40+ implementations** of `__str__()`, `__repr__()`, and `to_string()` methods across the codebase with inconsistent behavior:

```python
# Some classes:
class Formula:
    def __str__(self): ...
    def to_string(self): ...  # Duplicates __str__


# Others:
class Term:
    def __str__(self): ...

    # No to_string()


# Yet others:
class Operator:
    def to_string(self): ...

    # No __str__()
```

#### Proposed Solution

Create a `Stringifiable` mixin:

```python
# native/mixins.py (new file)
from abc import ABC, abstractmethod
from typing import Dict, Any


class Stringifiable(ABC):
    """
    Mixin for classes that need string representation.

    Provides consistent __str__, __repr__, and to_string() methods.
    Subclasses only need to implement _to_string_parts().
    """

    @abstractmethod
    def _to_string_parts(self) -> Dict[str, Any]:
        """
        Return dict of parts to include in string representation.

        Example:
            return {
                'type': 'AtomicFormula',
                'predicate': self.predicate,
                'terms': self.terms,
            }
        """
        pass

    def to_string(self, verbose: bool = False) -> str:
        """Generate string representation."""
        parts = self._to_string_parts()
        if verbose:
            return (
                f"{parts['type']}({', '.join(f'{k}={v}' for k, v in parts.items() if k != 'type')})"
            )
        else:
            return self._format_simple(parts)

    def __str__(self) -> str:
        return self.to_string(verbose=False)

    def __repr__(self) -> str:
        return self.to_string(verbose=True)

    def _format_simple(self, parts: Dict[str, Any]) -> str:
        """Override for custom simple formatting."""
        return str(parts)
```

Usage:

```python
# Before:
class AtomicFormula:
    def __str__(self):
        return f"{self.predicate}({', '.join(map(str, self.terms))})"

    def to_string(self):
        return self.__str__()


# After:
class AtomicFormula(Stringifiable):
    def _to_string_parts(self):
        return {
            "type": "AtomicFormula",
            "predicate": self.predicate,
            "terms": self.terms,
        }
```

#### Implementation Steps

1. **Week 1: Create mixin**
   - Implement `Stringifiable` mixin
   - Add comprehensive tests

2. **Week 1-2: Migrate classes (batch 1)**
   - Migrate Formula classes
   - Update tests

3. **Week 2: Migrate classes (batch 2)**
   - Migrate Term classes
   - Migrate Operator classes

4. **Week 2-3: Migrate remaining**
   - Migrate all other classes
   - Remove duplicate methods
   - Final validation

#### Success Criteria

- ✅ All classes use `Stringifiable` mixin
- ✅ Zero duplicate `__str__` / `to_string()` implementations
- ✅ Consistent behavior across all classes
- ✅ All tests passing
- ✅ Reduce code by ~500 LOC

---

### Issue P1-3: Type Safety Gaps

#### Problem Statement

Heavy use of `Any` type hints reduces type safety:

```python
# Current:
def apply_rule(self, formulas: List[Any]) -> Any: ...


# Better:
def apply_rule(self, formulas: List[Formula]) -> List[Formula]: ...
```

#### Proposed Solution

1. **Replace `Any` with specific types**
2. **Use `Protocol` for duck typing**
3. **Use `TypeVar` for generics**
4. **Add `typing.TYPE_CHECKING` for forward references**

Example:

```python
from typing import Protocol, TypeVar, List
from abc import abstractmethod


class Formulaic(Protocol):
    """Protocol for formula-like objects."""

    @abstractmethod
    def to_string(self) -> str: ...


T = TypeVar("T", bound=Formulaic)


def process_formulas(formulas: List[T]) -> List[T]: ...
```

#### Implementation Steps

1. **Week 1: Audit `Any` usage**
   - Identify all uses of `Any`
   - Categorize by complexity

2. **Week 1-2: Replace simple cases**
   - Replace obvious `Any` → concrete types
   - Run mypy validation

3. **Week 2-3: Add Protocols**
   - Define Protocol classes
   - Use for duck typing

4. **Week 3: Add generics**
   - Use TypeVar where appropriate
   - Improve type inference

#### Success Criteria

- ✅ Reduce `Any` usage by 70%
- ✅ `mypy` error count → 0
- ✅ Better IDE autocomplete
- ✅ Catch type errors at compile time

---

### Issue P1-4: Missing API Documentation

#### Problem Statement

While there are many documentation files, there's no comprehensive API reference showing:
- All public classes and methods
- Parameters and return types
- Usage examples
- Common patterns

#### Proposed Solution

Create `API_REFERENCE_v2.md` with:
1. Auto-generated API docs from docstrings
2. Usage examples for each major class
3. Common usage patterns
4. Migration guide from legacy APIs

Could use tools like:
- `pydoc` for extraction
- `sphinx` for generation
- Manual curation for quality

#### Implementation Steps

1. **Week 1: Generate skeleton**
   - Extract all public APIs
   - Create structure

2. **Week 1-2: Add examples**
   - Add usage examples for 50 most-used APIs
   - Add common patterns

3. **Week 2: Review and polish**
   - Internal review
   - Add cross-references
   - Ensure accuracy

#### Success Criteria

- ✅ API reference >10,000 words
- ✅ Examples for 50+ APIs
- ✅ Auto-generated from code
- ✅ Searchable structure

---

## 🟢 Medium Priority Issues (P2)

### Issue P2-1: Adapter Pattern for External Provers

#### Problem Statement

Z3, Vampire, and E-Prover adapters duplicate connection/configuration logic.

#### Proposed Solution

Create `BaseProverAdapter` abstract class:

```python
from abc import ABC, abstractmethod
from typing import Dict, Any, Optional


class BaseProverAdapter(ABC):
    """Base class for external theorem prover adapters."""

    def __init__(self, config: Optional[Dict[str, Any]] = None):
        self.config = config or {}
        self._connection = None
        self._initialize()

    @abstractmethod
    def _initialize(self):
        """Initialize prover connection."""
        pass

    @abstractmethod
    def prove(self, formula: Formula) -> ProofResult:
        """Prove formula."""
        pass

    def _handle_timeout(self, timeout: int):
        """Common timeout handling."""
        ...

    def _parse_output(self, output: str) -> ProofResult:
        """Common output parsing."""
        ...
```

#### Implementation Effort

- **Time:** 1-2 weeks
- **Impact:** Moderate (reduces adapter code by ~30%)

---

### Issue P2-2: Enhanced Exception Hierarchy

#### Problem Statement

Current `exceptions.py` has 8 exceptions with boilerplate `__init__`:

```python
class ValidationError(Exception):
    def __init__(self, message):
        self.message = message
        super().__init__(self.message)
```

#### Proposed Solution

Use dataclasses for cleaner exceptions:

```python
from dataclasses import dataclass


@dataclass
class ValidationError(Exception):
    message: str
    field: Optional[str] = None
    value: Optional[Any] = None

    def __str__(self):
        if self.field:
            return f"Validation failed for {self.field}: {self.message}"
        return self.message
```

#### Implementation Effort

- **Time:** 1 week
- **Impact:** Low (cleaner code, better error messages)

---

### Issue P2-3: Performance Profiling Utilities

#### Problem Statement

`profiling_utils.py` (393 LOC) could be enhanced with:
- Automatic profiling decorators
- Memory profiling
- Visualization support

#### Proposed Enhancement

```python
from functools import wraps
import time
import tracemalloc


def profile_performance(func):
    """Decorator to profile function performance."""

    @wraps(func)
    def wrapper(*args, **kwargs):
        tracemalloc.start()
        start_time = time.perf_counter()

        result = func(*args, **kwargs)

        end_time = time.perf_counter()
        current, peak = tracemalloc.get_traced_memory()
        tracemalloc.stop()

        print(f"{func.__name__}:")
        print(f"  Time: {end_time - start_time:.4f}s")
        print(f"  Memory: {peak / 1024 / 1024:.2f} MB")

        return result

    return wrapper
```

#### Implementation Effort

- **Time:** 1-2 weeks
- **Impact:** Moderate (better performance insights)

---

## 🔵 Low Priority Issues (P3)

### Issue P3-1: Consolidate Legacy Submodule Documentation

Archive historical docs about submodules since native implementation is mature.

**Effort:** 1 week

### Issue P3-2: Add More Type Hints to Tests

Test files could benefit from better type hints.

**Effort:** 1-2 weeks

### Issue P3-3: Performance Benchmarking Suite

Create comprehensive benchmarks comparing:
- Native vs submodules
- Different proving strategies
- Cache hit rates

**Effort:** 2-3 weeks

---

## 🗺️ Refactoring Roadmap

### Overview

**Total Duration:** 12-16 weeks  
**Total Effort:** 90-120 hours  
**Team Size:** 1-2 developers

### Phase 1: File Splitting (P0-1)

**Duration:** 3-4 weeks  
**Effort:** 25-35 hours

**Goals:**
- Split `prover_core.py` (2,927 → <600 LOC)
- Split `dcec_core.py` (1,360 → <600 LOC)
- Create inference rules package
- Create types package

**Milestones:**
- Week 1: Package structure created
- Week 2: Inference rules extracted
- Week 3: Prover components split
- Week 4: Type system split, validation

**Success Metrics:**
- ✅ No file >600 LOC
- ✅ All tests passing
- ✅ Maintainability index >75

---

### Phase 2: Code Consolidation (P0-2)

**Duration:** 2-3 weeks  
**Effort:** 15-20 hours

**Goals:**
- Consolidate language parsers (1,814 → 1,000 LOC)
- Create `MultilingualParser`
- Extract vocabularies to configs

**Milestones:**
- Week 1: Create unified parser
- Week 2: Extract vocabularies
- Week 2-3: Deprecate old parsers, validation

**Success Metrics:**
- ✅ Single parser for all languages
- ✅ 45% code reduction
- ✅ All language tests passing

---

### Phase 3: Documentation (P0-3, P1-4)

**Duration:** 2-3 weeks  
**Effort:** 15-20 hours

**Goals:**
- Create ARCHITECTURE.md
- Create API_REFERENCE_v2.md
- Update existing docs

**Milestones:**
- Week 1: Architecture documentation
- Week 2: API reference
- Week 3: Review and polish

**Success Metrics:**
- ✅ Architecture doc >5,000 words
- ✅ API reference >10,000 words
- ✅ Onboarding time <2 hours

---

### Phase 4: Type Safety (P1-3)

**Duration:** 2-3 weeks  
**Effort:** 15-25 hours

**Goals:**
- Reduce `Any` usage by 70%
- Add Protocol classes
- Add TypeVar generics
- Achieve mypy compliance

**Milestones:**
- Week 1: Replace simple `Any` cases
- Week 2: Add Protocols and TypeVars
- Week 3: Validation and polish

**Success Metrics:**
- ✅ mypy error count = 0
- ✅ 70% reduction in `Any` usage
- ✅ Better IDE support

---

### Phase 5: Import Organization (P1-1)

**Duration:** 1-2 weeks  
**Effort:** 10-15 hours

**Goals:**
- Add `__all__` exports to all modules
- Convert to absolute imports
- Handle optional dependencies
- Detect circular imports

**Milestones:**
- Week 1: Add exports, convert imports
- Week 2: Optional deps, validation

**Success Metrics:**
- ✅ All modules have `__all__`
- ✅ Zero circular imports
- ✅ Import time <1 second

---

### Phase 6: Code Quality Polish (P1-2, P2)

**Duration:** 2-3 weeks  
**Effort:** 10-15 hours

**Goals:**
- Create `Stringifiable` mixin
- Migrate all classes
- Create `BaseProverAdapter`
- Enhance exceptions

**Milestones:**
- Week 1: Create mixin, migrate batch 1
- Week 2: Migrate batch 2, adapter
- Week 3: Exceptions, validation

**Success Metrics:**
- ✅ Consistent string representation
- ✅ ~500 LOC reduction
- ✅ Cleaner adapter code

---

## 📊 Success Metrics

### Quantitative Metrics

| Metric | Baseline | Target | Measurement |
|--------|----------|--------|-------------|
| **Largest File Size** | 2,927 LOC | <600 LOC | wc -l |
| **Code Duplication** | ~40% | <5% | PMD/CPD |
| **Test Coverage** | 80-85% | >85% | pytest-cov |
| **Type Safety** | ~60% | >90% | mypy strict |
| **Maintainability Index** | ~55 | >75 | radon |
| **Import Time** | Baseline | <1s | time python -c "import CEC" |
| **mypy Errors** | Unknown | 0 | mypy --strict |
| **Total LOC** | 24,286 | ~22,500 | -7% |

### Qualitative Metrics

| Aspect | Before | After | How to Measure |
|--------|--------|-------|----------------|
| **Onboarding Time** | 8-16 hours | <2 hours | Developer survey |
| **Feature Add Time** | High | Low | Time tracking |
| **Bug Fix Time** | Moderate | Low | Issue metrics |
| **Code Clarity** | Moderate | High | Code review |
| **Documentation** | Fragmented | Unified | Review |

### Per-Phase Success Criteria

**Phase 1 (File Splitting):**
- ✅ prover_core.py split into 8 modules
- ✅ dcec_core.py split into 6 modules
- ✅ All 208+ tests passing
- ✅ No file >600 LOC

**Phase 2 (Consolidation):**
- ✅ Language parsers: 3 files → 1 file
- ✅ Code reduction: 1,814 → 1,000 LOC
- ✅ Easy language addition (200 LOC)

**Phase 3 (Documentation):**
- ✅ ARCHITECTURE.md created (>5,000 words)
- ✅ API_REFERENCE_v2.md created (>10,000 words)
- ✅ Developer onboarding <2 hours

**Phase 4 (Type Safety):**
- ✅ `Any` usage reduced 70%
- ✅ mypy --strict passes
- ✅ Better IDE autocomplete

**Phase 5 (Imports):**
- ✅ All modules have `__all__`
- ✅ Zero circular imports
- ✅ Optional dependencies handled

**Phase 6 (Polish):**
- ✅ Consistent string representation
- ✅ Cleaner adapter pattern
- ✅ Enhanced exceptions

---

## 📖 Implementation Guidelines

### General Principles

1. **Incremental Changes**
   - Make small, testable changes
   - Run tests after each change
   - Commit frequently

2. **Backward Compatibility**
   - Maintain existing APIs during transition
   - Use deprecation warnings
   - Provide migration guides

3. **Test-Driven**
   - Write tests first when adding features
   - Maintain >85% coverage
   - Add regression tests for bugs

4. **Documentation**
   - Update docs with code changes
   - Add docstrings to all public APIs
   - Keep examples up-to-date

5. **Code Review**
   - All changes reviewed
   - Automated checks (linting, type checking)
   - Performance validation

### Coding Standards

**Python Style:**
- Follow PEP 8
- Use Black formatter
- Use isort for imports
- Maximum line length: 100 characters

**Type Hints:**
- All public functions have type hints
- Use Protocol for duck typing
- Use TypeVar for generics
- Avoid `Any` when possible

**Documentation:**
- Google-style docstrings
- Include examples in docstrings
- Document exceptions raised
- Add usage notes where helpful

**Testing:**
- Use pytest
- Follow GIVEN-WHEN-THEN format
- Aim for >85% coverage
- Include edge cases

### Git Workflow

```bash
# 1. Create feature branch
git checkout -b refactor/split-prover-core

# 2. Make incremental changes
git add native/inference_rules/
git commit -m "Extract propositional inference rules"

# 3. Run tests continuously
pytest tests/unit_tests/logic/CEC/

# 4. Push and create PR
git push origin refactor/split-prover-core

# 5. Review and merge
# After approval, merge to main
```

### Testing Strategy

**Unit Tests:**
- Test individual functions/classes
- Mock external dependencies
- Fast execution (<1s per test)

**Integration Tests:**
- Test component interactions
- Use real dependencies
- Moderate execution (<10s per test)

**Regression Tests:**
- Test bug fixes don't reappear
- Include in CI/CD
- Document bug number

**Performance Tests:**
- Benchmark critical paths
- Compare before/after
- Track over time

### Review Checklist

**Code Quality:**
- ✅ Follows PEP 8
- ✅ Has type hints
- ✅ Has docstrings
- ✅ No linting errors
- ✅ mypy passes

**Testing:**
- ✅ New code has tests
- ✅ All tests passing
- ✅ Coverage >85%
- ✅ No test warnings

**Documentation:**
- ✅ Updated relevant docs
- ✅ Added examples
- ✅ Updated CHANGELOG

**Performance:**
- ✅ No performance regression
- ✅ Benchmark results acceptable
- ✅ Memory usage acceptable

---

## ⚠️ Risk Management

### High Risks

#### Risk H-1: Breaking Existing Functionality

**Probability:** Medium  
**Impact:** High  
**Mitigation:**
- Comprehensive test suite (208+ tests)
- Run tests after every change
- Keep deprecated code temporarily
- Staged rollout

#### Risk H-2: Import Circular Dependencies

**Probability:** Medium  
**Impact:** Medium  
**Mitigation:**
- Use absolute imports
- Careful dependency planning
- Import checker in CI
- Layered architecture

### Medium Risks

#### Risk M-1: Developer Resistance to Change

**Probability:** Low  
**Impact:** Medium  
**Mitigation:**
- Clear communication
- Show benefits
- Provide migration guides
- Incremental adoption

#### Risk M-2: Performance Regression

**Probability:** Low  
**Impact:** Medium  
**Mitigation:**
- Benchmark before/after
- Performance test suite
- Profile critical paths
- Optimize if needed

### Low Risks

#### Risk L-1: Documentation Staleness

**Probability:** Medium  
**Impact:** Low  
**Mitigation:**
- Documentation in code (docstrings)
- Automated generation where possible
- Regular reviews
- CI checks for docs

#### Risk L-2: Type Checking False Positives

**Probability:** Medium  
**Impact:** Low  
**Mitigation:**
- Use `# type: ignore` sparingly
- Document why
- Review mypy config
- Improve type hints

---

## 📅 Timeline Summary

### Gantt Chart (Text)

```
Week 1-4:   Phase 1: File Splitting              [P0-1] ████████████
Week 3-5:   Phase 2: Code Consolidation          [P0-2]       ██████
Week 5-7:   Phase 3: Documentation               [P0-3, P1-4]   ██████
Week 7-9:   Phase 4: Type Safety                 [P1-3]           ██████
Week 9-10:  Phase 5: Import Organization         [P1-1]               ████
Week 10-12: Phase 6: Code Quality Polish         [P1-2, P2]             ██████
```

### Milestone Schedule

| Week | Milestone | Deliverable |
|------|-----------|-------------|
| 1 | Phase 1 Start | Package structures created |
| 2 | Inference Rules | Rules extracted to modules |
| 3 | Prover Split | Prover components split |
| 4 | Phase 1 Complete | No file >600 LOC, all tests pass |
| 5 | Phase 2 Complete | Unified multilingual parser |
| 7 | Phase 3 Complete | Architecture + API docs |
| 9 | Phase 4 Complete | Type safety >90%, mypy passes |
| 10 | Phase 5 Complete | Clean imports, no circular deps |
| 12 | Phase 6 Complete | All polish items done |
| 12 | **Project Complete** | All success metrics met |

---

## 🎯 Quick Reference

### Priority Matrix

```
           │ High Impact        │ Medium Impact     │ Low Impact
───────────┼────────────────────┼──────────────────┼────────────────
High Effort│ P0-1: File Split   │ P1-3: Type Safety│ P3-3: Benchmarks
           │ P0-3: Architecture │                  │
───────────┼────────────────────┼──────────────────┼────────────────
Med Effort │ P0-2: Consolidate  │ P2-1: Adapters   │ P3-2: Test Types
           │ P1-4: API Docs     │ P2-3: Profiling  │
───────────┼────────────────────┼──────────────────┼────────────────
Low Effort │ P1-1: Imports      │ P2-2: Exceptions │ P3-1: Archive
           │ P1-2: Stringifiable│                  │
```

### Top 5 Actions

1. **Split prover_core.py** (2,927 → <600 LOC) - P0
2. **Consolidate language parsers** (1,814 → 1,000 LOC) - P0
3. **Create ARCHITECTURE.md** (>5,000 words) - P0
4. **Improve type safety** (mypy compliance) - P1
5. **Add __all__ exports** (all 57 modules) - P1

### Expected Outcomes

**After 12 weeks:**
- ✅ 7% code reduction (24,286 → ~22,500 LOC)
- ✅ 45% duplication reduction
- ✅ 75+ maintainability index
- ✅ 90%+ type safety
- ✅ Comprehensive documentation
- ✅ Zero circular imports
- ✅ <2 hour onboarding time

---

## 📞 Contact & Support

**Repository:** https://github.com/endomorphosis/ipfs_datasets_py  
**Issues:** https://github.com/endomorphosis/ipfs_datasets_py/issues  
**Maintainers:** IPFS Datasets Team

---

**Document Version:** 3.0  
**Last Updated:** 2026-02-19  
**Next Review:** 2026-03-01  
**Status:** Active Development

---

*This document is a living plan and will be updated as implementation progresses.*
