// ============================================================================
// 1M+ CONTEXT WINDOW LIMITS & WORKING MEMORY ENGINE
// Based on Tobias Schnabel's TDS Guide & Microsoft Research BAPO Model (2025-2026)
// ============================================================================

export const BAPO_THEORY_STEPS = [
  {
    step: 1,
    title: "Context Window vs. Working Memory Bottleneck",
    description: "Frontier LLMs feature 200k to 2M token context windows. However, context window size is raw capacity; effective working memory is the model's ability to track & reason over active variables simultaneously."
  },
  {
    step: 2,
    title: "Prefix Bandwidth (a)",
    description: "Measures how many bits of information can be compressed & passed forward in contextual embeddings while reading text (memorisation while reading)."
  },
  {
    step: 3,
    title: "Attention Bandwidth (b)",
    description: "Measures how many past token locations can be attended to at the query token (flipping back through pages)."
  },
  {
    step: 4,
    title: "Working Memory Capacity Boundary",
    description: "For BAPO-Hard tasks (e.g. variable tracking, graph reachability, majority consensus), when active variable complexity exceeds N = 5 to 10, performance rapidly regresses to random guessing (50%)."
  }
];

export const BAPO_TASK_TAXONOMY = [
  {
    name: "Graph Reachability & Variable Tracking",
    type: "BAPO-Hard",
    memoryDemand: "High (O(N) active state tracking)",
    description: "Tracing code variable assignments, multi-step logical deduction, entity relationship tracking.",
    recommendation: "Outsource to external Python execution runtime or use test-time reasoning tokens."
  },
  {
    name: "Majority Consensus & Sentiment Aggregation",
    type: "BAPO-Hard",
    memoryDemand: "High (Requires tracking global counts across whole context)",
    description: "Counting majority opinions, aggregating product reviews, consensus summarization.",
    recommendation: "Classify items individually (BAPO-Easy), then aggregate counts in Python."
  },
  {
    name: "Knowledge Graph Triple Reasoning",
    type: "BAPO-Hard",
    memoryDemand: "High (Multi-hop path construction across dense nodes)",
    description: "Constructing complex answers by linking disparate entity facts across long documents.",
    recommendation: "Pre-annotate data or pre-combine graph edges prior to prompting."
  },
  {
    name: "Needle-in-a-Haystack Lookup",
    type: "BAPO-Easy",
    memoryDemand: "Low (Requires locating a single isolated token string)",
    description: "Finding a specific password, date, or named entity inside a 1M token document.",
    recommendation: "Standard long context prompt works directly with high accuracy."
  },
  {
    name: "Document Equality & Difference Check",
    type: "BAPO-Easy",
    memoryDemand: "Low (Requires local pairwise comparison)",
    description: "Checking if two text documents or JSON payloads match.",
    recommendation: "Standard LLM or text diffing utility works effectively."
  }
];

export const SIMULATE_VARIABLE_TRACKING = (numVars = 6) => {
  // Generate variable chain:
  // x0 = "a", x1 = "b"
  // x2 = x0, x3 = x1, x4 = x2, x5 = x3 ...
  const lines = [
    `x0 = "a"`,
    `x1 = "b"`
  ];

  let targetVar = `x${numVars - 1}`;
  let currentVal = (numVars % 2 === 0) ? 'a' : 'b';

  for (let i = 2; i < numVars; i++) {
    const prevVar = `x${i - 2}`;
    lines.push(`x${i} = ${prevVar}`);
  }

  // Calculate estimated LLM accuracy based on empirical BAPO curves:
  // N <= 4: ~98%
  // N = 6: ~82%
  // N = 8: ~65%
  // N = 10: ~52% (Random guessing threshold ~50%)
  let accuracy = 98 - Math.pow(Math.max(0, numVars - 3), 1.6) * 12;
  accuracy = Math.max(50, Math.min(99, Math.round(accuracy)));

  return {
    numVars,
    lines,
    targetVar,
    currentVal,
    accuracy,
    isRandomGuessing: accuracy <= 52
  };
};

export const PYTHON_WORKING_MEMORY_CODE = `# ============================================================================
# WORKING MEMORY BOTTLENECK & ENGINEERING FIXES (PYTHON / BAPO MODEL)
# Based on Tobias Schnabel (Microsoft Research, TDS 2025)
# ============================================================================

import openai

# ── 1. The BAPO-Hard Variable Tracking Problem ─────────────────────────────
code_context = """
x6 = "a"
x4 = "b"
x0 = x6
x2 = x4
x3 = x0
x8 = x2
x9 = x3
x7 = x3
"""
# Direct LLM prompting on this 8-variable chain fails (~50% accuracy)
# because the LLM exceeds its effective working memory capacity (N > 5-10).

# ── 2. Fix 1: Outsourcing BAPO-Hard Tasks to External Python Runtime ────────
def solve_variable_tracking_via_python(code_snippet: str, target_var: str) -> str:
    """Outsource variable tracking computation to Python exec environment"""
    local_scope = {}
    exec(code_snippet, {}, local_scope)
    return local_scope.get(target_var, "Undefined")

result = solve_variable_tracking_via_python(code_context, "x7")
print(f"Python Outsourced Result for x7: '{result}' (100% Deterministic Accuracy)")

# ── 3. Fix 2: BAPO-Easy Decomposed Majority Aggregation ─────────────────────
reviews = [
  "Great product, highly recommend!",
  "Terrible quality, broke on day one.",
  "Awesome customer service and fast shipping.",
  "Not worth the price, disappointing."
]

def classify_single_review(review: str) -> int:
    """Classify 1 review at a time (BAPO-Easy task: Low memory demand)"""
    client = openai.OpenAI()
    res = client.chat.completions.create(
        model="gpt-4o-mini",
        messages=[{"role": "user", "content": f"Is this positive? Output 1 or 0: {review}"}]
    )
    return int(res.choices[0].message.content.strip())

# Aggregate in Python instead of asking LLM to count 1,000 reviews at once!
positive_count = sum(classify_single_review(r) for r in reviews)
print(f"Aggregated Positive Count: {positive_count} / {len(reviews)}")
`;
