# Blind Test Plan: Real-World Code Translation

## Objective
Test the entire Promptware translation system end-to-end with complex, real-world code using independent agents who don't know the expected results.

## Test Strategy

### Phase 1: Create Complex Python Code
**Agent**: Python Code Generator (independent)
- Task: Create non-trivial Python code with:
  - List/dict comprehensions
  - Classes with methods
  - Error handling (try/except)
  - Multiple functions
  - Control flow (if/for/while)
  - Type annotations
- **Constraint**: Agent doesn't know about Promptware or translation requirements
- **Output**: `test_code.py`

### Phase 2: Python → All Languages (Forward Translation)
**Agents**: 5 independent translation agents (Python/JS/Go/Rust/C#)
- Each agent gets ONLY the Python code
- Task: Use Promptware to translate Python → their assigned language
- **They don't know**: What other agents are doing or expected results
- **Output**:
  - `test_code.js`
  - `test_code.go`
  - `test_code.rs`
  - `test_code.cs`

### Phase 3: All Languages → Python (Reverse Translation)
**Agent**: Python Reverse Translator (independent)
- Gets the 4 generated files (JS, Go, Rust, C#)
- Task: Translate each back to Python using Promptware
- **They don't know**: Original Python code
- **Output**:
  - `from_js.py`
  - `from_go.py`
  - `from_rust.py`
  - `from_csharp.py`

### Phase 4: Analysis & Comparison
**Agent**: Code Analyzer (independent)
- Gets all 9 files (1 original + 4 forward + 4 reverse)
- Task: Compare semantic equivalence
- Metrics:
  - Syntax validity
  - Semantic preservation
  - Feature coverage
  - Round-trip accuracy

## Success Criteria
- All generated code is syntactically valid
- Semantic equivalence >= 90%
- Collection operations preserved
- Control flow preserved
- Round-trip accuracy >= 85%

## Failure Analysis
If any test fails:
1. Identify which language pair failed
2. Identify which feature failed
3. Create targeted fix
4. Re-run blind test
