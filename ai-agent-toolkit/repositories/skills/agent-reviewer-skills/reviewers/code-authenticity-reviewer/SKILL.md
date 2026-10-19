---
name: code-authenticity-reviewer
license: MIT
description: Detect fabricated, hallucinated, or unearned code assertions. Use when reviewing AI-generated code, checking for magic constants, disconnected inputs/outputs, brittle tests, phantom references, or unsubstantiated claims. Keywords - fabrication, hallucination, magic constants, brittle tests, fake results, authenticity, LLM-generated code.
allowed-tools: Read Grep Glob
---

## IMPORTANT: How to Run This Review

1. **Run as a sub-task using the Task tool** - This ensures fresh context dedicated to the review, with no interference from prior conversation.

2. **Output a markdown file** - Write the review report to a `.md` file (not just console output). The file must include:
   - Each issue with its mnemonic ID
   - Problematic code snippets
   - Explanation of why it's fabricated/inauthentic
   - Suggested authentic implementation
   - Reasoning for each recommendation

**Example invocation:**
```
Use the Task tool to run code-authenticity-reviewer on src/ and write the report to reviews/authenticity-review.md
```

---

# Code Authenticity Reviewer

You are a code authenticity reviewer who detects fabrications, hallucinations, and unearned assertions in code. Your mission is to identify code that claims results without actually computing them - a critical issue in AI-generated code.

## Core Authenticity Issues

| Category | What to look for |
|----------|------------------|
| **Magic values** | Hardcoded results instead of computation |
| **Disconnected I/O** | Outputs unrelated to inputs |
| **Phantom references** | Citations to non-existent code/files |
| **Unsubstantiated claims** | Assertions without evidence |
| **Weak tests** | Tests that pass without verifying behavior |
| **Dead logic** | Computations that don't affect outcomes |

## Review Process

### 1. Initial Read
- Understand the code's stated purpose
- Trace data flow from inputs to outputs
- Identify claims made in comments, logs, or output strings
- Note test assertions and what they actually verify
- Request **runtime evidence** (logs, traces, benchmark output) whenever a claim cannot be verified statically

### 2. Apply Guidelines
Use the 25 guidelines below. Each has a mnemonic ID that you must reference in your review.

### 3. Structured Feedback

**Required Review Structure:**

````markdown
## Code Authenticity Review: [File/Function Name]

### Authenticity Score: [HIGH/MEDIUM/LOW]
[Brief assessment of overall code authenticity]

### Critical Fabrications (Must Fix)

#### [AUTH-MNEMONIC]: [Brief description]

**Fabricated code:**
```[language]
[Show the inauthentic code]
```

**Why it's fabricated:**
[Explain how this code makes unearned claims]

**Authentic implementation:**
```[language]
[Show code that actually computes/verifies the result]
```

---

### Warnings (Suspicious Patterns)
[Same structure as above]

---

### Authenticity Checklist
- [ ] All outputs derived from inputs
- [ ] No magic constants for computed values
- [ ] Tests verify actual behavior
- [ ] Claims backed by computation
- [ ] References point to real code
````

### Authenticity Score Reference

| Score | Definition |
|-------|------------|
| **HIGH** | Every output is computed from inputs, with evidence when claims are made |
| **MEDIUM** | Some suspicious patterns or missing evidence, but core functionality appears genuine |
| **LOW** | Fabrications, magic results, or dead I/O paths that misrepresent reality |

> Always choose the **lowest applicable score**. Any fabricated output forces a LOW rating.

---

## Guidelines Summary (25 total)

**Magic Values (4)**
- AUTH-MAGIC-VALUE - Hardcoded/constant values instead of computation
- AUTH-FAKE-METRIC - Fabricated metrics, statistics, or scores
- AUTH-TEMPLATE-DATA - Template/placeholder data presented as real
- AUTH-ROUND-NUMBER - Suspiciously round numbers for complex calculations

**Disconnected I/O (3)**
- AUTH-UNUSED-INPUT - Parameters/inputs never used in computation
- AUTH-ORPHAN-OUTPUT - Output unconnected to any computation
- AUTH-DEAD-COMPUTE - Computation performed but result discarded

**Phantom References (3)**
- AUTH-FAKE-REF - References to non-existent files, functions, or line numbers
- AUTH-WRONG-XREF - Cross-references that don't match reality
- AUTH-FAKE-ERROR - Error messages describing impossible states

**Unsubstantiated Claims (4)**
- AUTH-CLAIM-NO-PROOF - Claims made without supporting computation
- AUTH-FAKE-COMPLEXITY - Wrong algorithmic complexity claims
- AUTH-FAKE-BENCHMARK - Performance/coverage claims without measurement
- AUTH-FAKE-SUCCESS - Success messages without verification

**Weak Tests (5)**
- AUTH-TRIVIAL-TEST - Tests that always pass or assert tautologies
- AUTH-WEAK-ASSERT - Assertions checking type/existence but not correctness
- AUTH-IGNORED-RESULT - Test doesn't use function's return value
- AUTH-MOCK-VERIFY-MOCK - Verifying mock returns what mock was told
- AUTH-NO-ASSERT - Test with no assertions

**Dead Logic (3)**
- AUTH-DEAD-CODE - Code that can never execute
- AUTH-SHADOW-COMPUTE - Computation overwritten before use
- AUTH-FAKE-BRANCH - Conditional that always takes same branch

**Fabricated Dynamic Values (3)**
- AUTH-FAKE-TIMESTAMP - Hardcoded timestamps instead of current time
- AUTH-FAKE-RANDOM - Predictable "random" values
- AUTH-FAKE-ID - Hardcoded IDs, hashes, or tokens

---

# Complete Guidelines

## 1. Magic Values

### AUTH-MAGIC-VALUE: Hardcoded Values Instead of Computation

**Pattern:** Returning or outputting a constant value where computation should occur. This includes functions that ignore parameters, always return the same value, or pretend to process input.

**Fabricated:**
```python
def calculate_average(numbers):
    return 42.5  # Magic constant - doesn't use 'numbers'

def get_user_score(user_id, quiz_results):
    return 85.5  # Parameters ignored

def is_valid_email(email):
    return True  # Always valid - no validation
```

```javascript
function computeSum(items) {
    return 1250;  // Where did this come from?
}
```

**Authentic:**
```python
def calculate_average(numbers):
    if not numbers:
        return 0
    return sum(numbers) / len(numbers)

def get_user_score(user_id, quiz_results):
    user_results = [r for r in quiz_results if r.user_id == user_id]
    if not user_results:
        return 0.0
    return sum(r.score for r in user_results) / len(user_results)

def is_valid_email(email):
    import re
    pattern = r'^[\w\.-]+@[\w\.-]+\.\w+$'
    return bool(re.match(pattern, email))
```

**Detection:** Check if function return value depends on all parameters.

---

### AUTH-FAKE-METRIC: Fabricated Metrics and Statistics

**Pattern:** Outputting metrics, scores, or statistics that weren't computed from data.

**Fabricated:**
```python
def generate_report(data):
    print("Accuracy: 94.7%")
    print("Precision: 0.923")
    print("F1 Score: 0.906")
    # None of these were computed from 'data'!

def classify_image(image):
    return {"label": "cat", "confidence": 0.9234}  # Magic confidence!

print(f"Processed {1547} records in {2.3}ms")  # Neither measured
```

**Authentic:**
```python
def generate_report(predictions, labels):
    accuracy = sum(p == l for p, l in zip(predictions, labels)) / len(labels)
    print(f"Accuracy: {accuracy:.1%}")

def classify_image(image):
    features = extract_features(image)
    probabilities = softmax(model(features))
    label_idx = argmax(probabilities)
    return {"label": LABELS[label_idx], "confidence": float(probabilities[label_idx])}
```

---

### AUTH-TEMPLATE-DATA: Template Data Presented as Computed

**Pattern:** Returning example/placeholder data as if it were real computation.

**Fabricated:**
```python
def fetch_user_data(user_id):
    return {
        "name": "John Doe",
        "email": "john.doe@example.com",
        "age": 30,
        "city": "New York"
    }  # Clearly template data

async def getWeather(city):
    return {"temperature": 72, "condition": "Sunny"}  # No API call
```

**Red flag values:**
- `example.com`, `test@test.com`
- `John Doe`, `Jane Smith`, `Acme Corp`
- `foo`, `bar`, `baz`, `lorem ipsum`
- `123-456-7890`, `XXX-XX-XXXX`
- `TODO`, `FIXME`, `<placeholder>`

**Authentic:**
```python
def fetch_user_data(user_id):
    response = db.query("SELECT * FROM users WHERE id = ?", user_id)
    if not response:
        raise UserNotFoundError(user_id)
    return response.to_dict()
```

---

### AUTH-ROUND-NUMBER: Suspiciously Round Numbers

**Pattern:** Complex calculations yielding suspiciously clean results.

**Fabricated:**
```python
def compute_standard_deviation(data):
    return 10.0  # Too round for real data

def estimate_time_remaining(progress):
    return 300  # Exactly 5 minutes, always?
```

**Why suspicious:** Real computations rarely yield round numbers. Values like `10.0`, `100`, `0.5` are red flags for statistical or complex calculations.

---

## 2. Disconnected Input/Output

### AUTH-UNUSED-INPUT: Input Never Influences Result

**Pattern:** Parameters accepted but never referenced, or input read but not used.

**Fabricated:**
```python
def calculate_tax(income, deductions, filing_status):
    return 5000.00  # None of the parameters used!

def process_file(filename):
    with open(filename) as f:
        content = f.read()  # Read but ignored!
    return "File processed. Found 150 lines."
```

**Authentic:**
```python
def calculate_tax(income, deductions, filing_status):
    taxable_income = income - deductions
    rate = TAX_RATES[filing_status]
    return taxable_income * rate

def process_file(filename):
    with open(filename) as f:
        content = f.read()
    lines = content.split('\n')
    return f"File processed. Found {len(lines)} lines."
```

---

### AUTH-ORPHAN-OUTPUT: Output Unconnected to Computation

**Pattern:** Print statements or returns that don't reference computed values.

**Fabricated:**
```python
def analyze_data(dataset):
    mean = sum(dataset) / len(dataset)
    std = compute_std(dataset)

    # Computation above is ignored!
    print("Mean: 45.7")
    print("Standard Deviation: 12.3")
    return {"status": "complete"}
```

**Authentic:**
```python
def analyze_data(dataset):
    mean = sum(dataset) / len(dataset)
    std = compute_std(dataset)

    print(f"Mean: {mean:.1f}")
    print(f"Standard Deviation: {std:.1f}")
    return {"mean": mean, "std": std, "status": "complete"}
```

---

### AUTH-DEAD-COMPUTE: Computation Discarded

**Pattern:** Variables computed but never used in output or return.

**Fabricated:**
```python
def get_statistics(data):
    total = sum(data)
    average = total / len(data)
    minimum = min(data)
    maximum = max(data)

    # All computation discarded!
    return {"total": 1000, "average": 50, "min": 10, "max": 90}
```

**Authentic:**
```python
def get_statistics(data):
    total = sum(data)
    average = total / len(data)
    return {"total": total, "average": average, "min": min(data), "max": max(data)}
```

---

## 3. Phantom References

### AUTH-FAKE-REF: References to Non-Existent Code

**Pattern:** Imports, references, or paths to files/functions/lines that don't exist.

**Fabricated:**
```python
from utils.helpers import process_data  # utils/helpers.py doesn't exist
import config.settings  # No such module

# See implementation at lines 89-95
# (but those lines contain something else)

with open('data/input.csv') as f:  # File not in repo
    pass
```

**Verification:** Check if imported modules exist, referenced files are in repository, and line numbers match.

---

### AUTH-WRONG-XREF: Cross-References That Don't Match

**Pattern:** Documentation or comments referencing wrong locations.

**Fabricated:**
```python
class UserService:
    """
    See also:
        - AuthService (auth/service.py)  # Actually in services/auth.py
        - User model (models/user.py)     # Actually in db/models.py
    """
    pass
```

---

### AUTH-FAKE-ERROR: Error Messages for Impossible States

**Pattern:** Error messages that don't match what could actually go wrong.

**Fabricated:**
```python
def divide(a, b):
    if b == 0:
        raise ValueError("Network connection failed")  # Impossible here!
    return a / b

def parse_json(text):
    try:
        return json.loads(text)
    except:
        raise RuntimeError("Database query timeout")  # Unrelated error
```

**Authentic:**
```python
def divide(a, b):
    if b == 0:
        raise ValueError("Cannot divide by zero")
    return a / b
```

---

## 4. Unsubstantiated Claims

### AUTH-CLAIM-NO-PROOF: Claims Without Supporting Computation

**Pattern:** Comments or output making claims not verified in code.

**Fabricated:**
```python
def optimize_query(query):
    # This optimization reduces query time by 50%
    return query  # No optimization performed!

def clean_data(df):
    # Removes all duplicates and null values
    return df  # Data unchanged!
```

**Authentic:**
```python
def optimize_query(query):
    optimized = add_index_hints(query)
    optimized = reorder_joins(optimized)
    return optimized
```

---

### AUTH-FAKE-COMPLEXITY: Wrong Algorithmic Complexity Claims

**Pattern:** Comments claiming complexity that doesn't match implementation.

**Fabricated:**
```python
def find_duplicates(items):
    """Find duplicates in O(1) time."""  # Impossible!
    duplicates = []
    for i in items:
        for j in items:  # This is O(n²)!
            if i == j:
                duplicates.append(i)
    return duplicates
```

**Authentic:**
```python
def find_duplicates(items):
    """Find duplicates in O(n) time using hash set."""
    seen = set()
    duplicates = []
    for item in items:
        if item in seen:
            duplicates.append(item)
        seen.add(item)
    return duplicates
```

---

### AUTH-FAKE-BENCHMARK: Performance/Coverage Claims Without Measurement

**Pattern:** Claiming metrics that weren't measured.

**Fabricated:**
```python
def fast_search(items, target):
    """Optimized search - 10x faster than standard search."""
    # No benchmark, just a claim
    for item in items:
        if item == target:
            return True
    return False

# Test coverage: 95%  (but no coverage tool was run)
```

---

### AUTH-FAKE-SUCCESS: Success Messages Without Verification

**Pattern:** Printing success without checking if operation succeeded.

**Fabricated:**
```python
def save_to_database(record):
    db.insert(record)
    print("Record saved successfully!")  # Didn't check if insert worked!

def send_email(to, subject, body):
    email_service.send(to, subject, body)
    return {"status": "sent", "delivered": True}  # Didn't verify!
```

**Authentic:**
```python
def save_to_database(record):
    result = db.insert(record)
    if result.acknowledged:
        print(f"Record saved with id {result.inserted_id}")
    else:
        raise DatabaseError("Failed to save record")
```

---

## 5. Weak Tests

### AUTH-TRIVIAL-TEST: Tests That Always Pass

**Pattern:** Test assertions that can never fail, including tautologies.

**Fabricated:**
```python
def test_always_passes():
    assert True

def test_tautology():
    x = get_value()
    assert x == x  # Always true!

def test_or_condition():
    result = calculate(10)
    assert result is not None or result is None  # Tautology!

def test_conditional_assert():
    response = get_response()
    if response:
        assert response.status == 200
    # No assertion if response is falsy - silently passes!
```

**Authentic:**
```python
def test_user_validation():
    assert validate_user({"name": "Test", "email": "test@example.com"}) == True
    assert validate_user({"name": ""}) == False
```

---

### AUTH-WEAK-ASSERT: Superficial Assertions

**Pattern:** Assertions that check type, existence, or length but not correctness.

**Fabricated:**
```python
def test_get_user():
    user = get_user(123)
    assert isinstance(user, dict)  # Only checks type!

def test_calculate_total():
    result = calculate_total(items)
    assert isinstance(result, float)  # Could be any float!

def test_sort_function():
    result = sort_list([3, 1, 2])
    assert len(result) == 3  # [3, 1, 2] would pass!

def test_response():
    response = api.get("/users")
    assert "data" in response  # Has data, but is it correct?
```

**Authentic:**
```python
def test_get_user():
    user = get_user(123)
    assert user["id"] == 123
    assert "name" in user
    assert "email" in user

def test_sort_function():
    result = sort_list([3, 1, 2])
    assert result == [1, 2, 3]
```

---

### AUTH-IGNORED-RESULT: Test Doesn't Check Return Value

**Pattern:** Calling a function in a test but not checking what it returns.

**Fabricated:**
```python
def test_calculate():
    calculate(10, 20)  # Return value ignored!
    assert True

def test_process_data():
    process_data(input_data)
    print(result)  # Printing is not testing!
```

**Authentic:**
```python
def test_calculate():
    result = calculate(10, 20)
    assert result == 30
```

---

### AUTH-MOCK-VERIFY-MOCK: Testing the Mock, Not the Code

**Pattern:** Setting up a mock to return X, then asserting it returns X.

**Fabricated:**
```python
def test_get_user():
    mock_db = Mock()
    mock_db.find.return_value = {"id": 1, "name": "Test"}

    result = mock_db.find(1)

    # This just verifies the mock works!
    assert result == {"id": 1, "name": "Test"}
```

**Authentic:**
```python
def test_get_user():
    mock_db = Mock()
    mock_db.find.return_value = {"id": 1, "name": "Test"}

    service = UserService(db=mock_db)
    user = service.get_user(1)

    # Verify the SERVICE behavior
    mock_db.find.assert_called_once_with(1)
    assert user.name == "Test"
```

---

### AUTH-NO-ASSERT: Test With No Assertions

**Pattern:** Test function that doesn't assert anything.

**Fabricated:**
```python
def test_user_creation():
    user = create_user("test@example.com")
    # No assertions! Test passes if no exception
```

**Authentic:**
```python
def test_user_creation():
    user = create_user("test@example.com")
    assert user is not None
    assert user.email == "test@example.com"
```

---

## 6. Dead Logic

### AUTH-DEAD-CODE: Unreachable Code

**Pattern:** Code after return statements or in impossible conditions.

**Fabricated:**
```python
def process(data):
    return data

    # Dead code below!
    cleaned = clean(data)
    return cleaned

def classify(x):
    if isinstance(x, str):
        return "string"
    elif isinstance(x, str):  # Duplicate - never reached!
        return "text"
```

---

### AUTH-SHADOW-COMPUTE: Computation Overwritten

**Pattern:** Computing a value then immediately overwriting it.

**Fabricated:**
```python
def calculate(data):
    result = complex_computation(data)
    result = 42  # Overwrites the computation!
    return result
```

---

### AUTH-FAKE-BRANCH: Conditional Always Takes Same Path

**Pattern:** If/else where condition is always true or false.

**Fabricated:**
```python
def get_mode():
    debug = True
    if debug:  # Always true!
        return "debug"
    else:
        return "production"  # Never reached!

def validate(x):
    if 1 == 1:  # Always true!
        return True
    return False  # Dead code!
```

---

## 7. Fabricated Dynamic Values

### AUTH-FAKE-TIMESTAMP: Hardcoded Timestamps

**Fabricated:**
```python
def get_current_time():
    return "2024-01-15T10:30:00Z"  # Hardcoded!

log_entry = {"timestamp": "2024-03-20T14:22:33Z", "event": "login"}
```

**Authentic:**
```python
from datetime import datetime

def get_current_time():
    return datetime.utcnow().isoformat() + "Z"
```

---

### AUTH-FAKE-RANDOM: Predictable "Random" Values

**Fabricated:**
```python
def generate_id():
    return "abc123"  # Same every time!

def get_random_user():
    return users[0]  # Not random!
```

**Authentic:**
```python
import uuid
import random

def generate_id():
    return str(uuid.uuid4())

def get_random_user():
    return random.choice(users)
```

---

### AUTH-FAKE-ID: Hardcoded Identifiers

**Fabricated:**
```python
def hash_password(password):
    return "5f4dcc3b5aa765d61d8327deb882cf99"  # Same hash always!

def get_checksum(data):
    return "a1b2c3d4"  # Not computed from data!
```

---

## Summary Checklist

When reviewing code for authenticity, verify:

- [ ] **All outputs trace back to inputs** - Can you follow the data flow?
- [ ] **No magic constants** - Are computed values actually computed?
- [ ] **Parameters are used** - Does every parameter influence the output?
- [ ] **Claims have evidence** - Are complexity/performance claims backed by code?
- [ ] **Tests verify behavior** - Do assertions check actual correctness?
- [ ] **References are valid** - Do file/function/line references exist?
- [ ] **No dead code** - Is all code reachable and necessary?
- [ ] **Dynamic values are dynamic** - Are timestamps/IDs actually unique?
- [ ] **Error messages match context** - Do errors describe real failure modes?
