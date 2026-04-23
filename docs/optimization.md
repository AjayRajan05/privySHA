# Optimization

PrivySHA's optimization engine systematically reduces token usage while preserving meaning, resulting in significant cost savings and faster responses.

---

## ⚡ Optimization Overview

### Why Optimization Matters

**Cost Impact:**
- **Before**: 120 tokens → $0.00036
- **After**: 38 tokens → $0.00011
- **Savings**: 68% cost reduction

**Performance Impact:**
- **Faster responses** - Fewer tokens to process
- **Lower latency** - Reduced API call time
- **Better reliability** - Shorter prompts, fewer errors

---

## 🎯 Optimization Techniques

### 1. Constraint Consolidation

```python
# Input: Redundant constraints
"Analyze data thoroughly, completely, and in detail"

# Optimized: Consolidated constraint
"Analyze data thoroughly"
```

### 2. Object Simplification

```python
# Input: Verbose object description
"comprehensive_customer_sales_dataset_with_demographics"

# Optimized: Essential object
"sales_data"
```

### 3. Style Optimization

```python
# Input: Wordy style
"Please provide a detailed and comprehensive analysis"

# Optimized: Concise style
"Analyze thoroughly"
```

### 4. Semantic Compression

```python
# Input: Redundant phrases
"I would like you to please analyze the dataset and find any patterns or anomalies"

# Optimized: Core meaning
"Analyze dataset for patterns"
```

---

## 📊 Optimization Levels

### Conservative (Safe)

```python
agent = Agent(optimization_level="conservative")
```

**Characteristics:**
- **Token reduction**: 20-30%
- **Meaning preservation**: 99%
- **Risk**: Very low
- **Use case**: Critical applications

**Example:**
```python
# Before: 45 tokens
"Please analyze the data and provide insights"

# After: 32 tokens
"Analyze data and provide insights"
```

### Balanced (Recommended)

```python
agent = Agent(optimization_level="balanced")
```

**Characteristics:**
- **Token reduction**: 40-60%
- **Meaning preservation**: 95%
- **Risk**: Low
- **Use case**: General applications

**Example:**
```python
# Before: 78 tokens
"I would like you to please thoroughly analyze the customer data and identify any patterns"

# After: 35 tokens
"Analyze customer data for patterns"
```

### Aggressive (Maximum)

```python
agent = Agent(optimization_level="aggressive")
```

**Characteristics:**
- **Token reduction**: 60-80%
- **Meaning preservation**: 85%
- **Risk**: Medium
- **Use case**: Cost-sensitive applications

**Example:**
```python
# Before: 120 tokens
"Could you please provide a comprehensive and detailed analysis of the sales dataset, focusing on identifying any unusual patterns or anomalies that might be present"

# After: 25 tokens
"Analyze sales data for anomalies"
```

---

## 🔧 Optimization Engine

### Core Components

```python
from privysha.compiler.optimizer_engine import PromptOptimizer

optimizer = PromptOptimizer(
    level="balanced",
    preserve_semantics=True,
    target_reduction=0.5
)
```

### Optimization Pipeline

```
Original Prompt
    ↓
Token Analysis
    ↓
Redundancy Detection
    ↓
Semantic Analysis
    ↓
Constraint Extraction
    ↓
Optimization Rules
    ↓
Semantic Validation
    ↓
Optimized Prompt
```

### Stage 1: Token Analysis

```python
# Analyze token structure
tokens = tokenize(prompt)
token_analysis = analyze_tokens(tokens)

# Example analysis
{
    "total_tokens": 78,
    "content_tokens": 45,
    "stop_words": 15,
    "redundant_phrases": 8,
    "filler_words": 10
}
```

### Stage 2: Redundancy Detection

```python
# Find redundant patterns
redundancies = detect_redundancies(prompt)

# Example redundancies
{
    "repeated_words": ["thoroughly", "completely"],
    "redundant_phrases": ["analyze and examine"],
    "filler_patterns": ["please", "could you"],
    "wordy_expressions": ["in order to", "due to the fact that"]
}
```

### Stage 3: Semantic Analysis

```python
# Preserve core meaning
semantics = analyze_semantics(prompt)
core_meaning = extract_core_intent(semantics)

# Example semantics
{
    "core_intent": "analyze",
    "target_object": "data",
    "key_constraints": ["thorough"],
    "optional_modifiers": ["please", "comprehensive"]
}
```

### Stage 4: Optimization Rules

```python
# Apply optimization rules
optimized_prompt = apply_optimization_rules(prompt, analysis)

# Rule examples
OPTIMIZATION_RULES = {
    "remove_fillers": ["please", "could you", "I would like"],
    "consolidate_constraints": {
        "thoroughly, completely, in detail": "thoroughly",
        "quickly, fast, promptly": "quickly"
    },
    "simplify_objects": {
        "comprehensive_customer_data": "customer_data",
        "detailed_sales_report": "sales_report"
    },
    "compress_phrases": {
        "in order to": "to",
        "due to the fact that": "because",
        "with regard to": "about"
    }
}
```

---

## 📈 Optimization Metrics

### Real-time Metrics

```python
result = agent.run("Analyze comprehensive customer data thoroughly", trace=True)

print(result["optimization_metrics"])
# {
#   "original_tokens": 65,
#   "optimized_tokens": 22,
#   "reduction_percentage": 66.2,
#   "meaning_preservation_score": 0.94,
#   "optimization_time_ms": 12
# }
```

### Performance Analytics

```python
# Get optimization statistics
stats = agent.get_optimization_stats()
# {
#   "total_optimizations": 1250,
#   "average_reduction": 63.4,
#   "total_tokens_saved": 45678,
#   "cost_savings_usd": 12.34,
#   "meaning_preservation_avg": 0.92
# }
```

### Optimization Breakdown

```python
# Detailed optimization analysis
breakdown = agent.get_optimization_breakdown()
# {
#   "filler_removal": {"tokens_saved": 1234, "percentage": 15.2},
#   "constraint_consolidation": {"tokens_saved": 2345, "percentage": 28.9},
#   "object_simplification": {"tokens_saved": 1876, "percentage": 23.1},
#   "phrase_compression": {"tokens_saved": 1567, "percentage": 19.3},
#   "semantic_optimization": {"tokens_saved": 1123, "percentage": 13.8}
# }
```

---

## 🎯 Custom Optimization

### Domain-Specific Optimization

```python
# Medical domain optimization
medical_optimizer = PromptOptimizer(
    domain="medical",
    custom_rules={
        "preserve_terms": ["diagnosis", "symptoms", "treatment"],
        "compress_phrases": {
            "patient presents with": "patient has",
            "examination reveals": "exam shows"
        }
    }
)

# Legal domain optimization
legal_optimizer = PromptOptimizer(
    domain="legal",
    custom_rules={
        "preserve_terms": ["contract", "liability", "compliance"],
        "compress_phrases": {
            "in accordance with": "per",
            "subsequent to": "after"
        }
    }
)
```

### Custom Optimization Rules

```python
# Add custom optimization rules
optimizer = PromptOptimizer()
optimizer.add_rule(
    name="custom_compression",
    pattern=r"(very|quite|rather)\s+(\w+)",
    replacement=r"\2",
    confidence=0.8
)

optimizer.add_rule(
    name="domain_specific",
    pattern=r"analyze\s+(customer|user)\s+data",
    replacement="analyze user data",
    confidence=0.9
)
```

### Optimization Constraints

```python
# Set optimization boundaries
optimizer = PromptOptimizer(
    constraints={
        "min_meaning_preservation": 0.9,
        "max_token_reduction": 0.7,
        "preserve_keywords": ["urgent", "critical", "security"],
        "forbidden_optimizations": ["acronyms", "technical_jargon"]
    }
)
```

---

## 🔍 Optimization Debugging

### Optimization Trace

```python
result = agent.run("Analyze data thoroughly", trace=True)

# Optimization trace
print(result["optimization_trace"])
# {
#   "stage": "optimization",
#   "original": "Please thoroughly analyze the comprehensive data",
#   "tokens": {"original": 8, "optimized": 4},
#   "rules_applied": [
#     {"rule": "remove_fillers", "change": "Please" → ""},
#     {"rule": "constraint_consolidation", "change": "thoroughly" → "thorough"},
#     {"rule": "object_simplification", "change": "comprehensive data" → "data"}
#   ],
#   "confidence": 0.94
# }
```

### A/B Testing

```python
# Test optimization effectiveness
ab_test = agent.test_optimization(
    original_prompt="Analyze comprehensive data thoroughly",
    variations=["conservative", "balanced", "aggressive"]
)

# Results
# {
#   "conservative": {"tokens": 6, "quality": 0.98},
#   "balanced": {"tokens": 4, "quality": 0.94},
#   "aggressive": {"tokens": 3, "quality": 0.87}
# }
```

### Optimization Validation

```python
# Validate optimization quality
validation = agent.validate_optimization(
    original="Analyze comprehensive data thoroughly",
    optimized="Analyze data thoroughly"
)

# {
#   "semantic_similarity": 0.92,
#   "intent_preservation": 0.95,
#   "constraint_preservation": 0.88,
#   "overall_quality": 0.92
# }
```

---

## 📊 Cost Analysis

### Token Cost Calculator

```python
# Calculate cost savings
cost_analysis = agent.calculate_cost_savings(
    original_tokens=120,
    optimized_tokens=38,
    model="gpt-4o-mini"
)

# {
#   "original_cost_usd": 0.00036,
#   "optimized_cost_usd": 0.00011,
#   "savings_usd": 0.00025,
#   "savings_percentage": 69.4
# }
```

### Monthly Projections

```python
# Project monthly savings
monthly_projection = agent.project_monthly_savings(
    daily_requests=1000,
    avg_original_tokens=120,
    avg_optimization_rate=0.65
)

# {
#   "monthly_tokens_saved": 2340000,
#   "monthly_cost_savings": 7.02,
#   "annual_savings": 84.24
# }
```

### ROI Analysis

```python
# Return on investment
roi = agent.calculate_optimization_roi(
    implementation_cost=50,  # Developer hours
    monthly_savings=7.02,
    period_months=12
)

# {
#   "total_savings": 84.24,
#   "net_return": 34.24,
#   "roi_percentage": 68.5,
#   "payback_period_months": 7.1
# }
```

---

## 🚀 Advanced Optimization

### Contextual Optimization

```python
# Optimize based on conversation context
context = [
    {"role": "user", "content": "Analyze sales data"},
    {"role": "assistant", "content": "Sales increased 15%"},
    {"role": "user", "content": "What about last year's comprehensive data?"}
]

# Context-aware optimization
optimized = agent.optimize_with_context(
    prompt="What about last year's comprehensive data?",
    context=context
)

# Result: "Compare with last year's data"
# (Understands "comprehensive" is redundant given context)
```

### Multi-Objective Optimization

```python
# Optimize for multiple objectives
multi_obj = agent.optimize_multi_objective(
    prompt="Analyze comprehensive data thoroughly",
    objectives=["cost", "quality", "speed"],
    weights={"cost": 0.5, "quality": 0.3, "speed": 0.2}
)

# {
#   "optimized_prompt": "Analyze data thoroughly",
#   "scores": {"cost": 0.9, "quality": 0.8, "speed": 0.85},
#   "overall_score": 0.86
# }
```

### Learning Optimization

```python
# Optimization that improves over time
agent = Agent(
    learning_optimization=True,
    feedback_loop=True,
    improvement_rate=0.05
)

# Learns from:
# - User feedback on quality
# - Performance metrics
# - Domain-specific patterns
# - Successful optimizations
```

---

## 🎯 Best Practices

### Production Optimization

```python
agent = Agent(
    optimization_level="balanced",
    optimization_config={
        "validate_quality": True,
        "min_quality_threshold": 0.85,
        "fallback_to_original": True,
        "log_optimizations": True
    }
)
```

### Monitoring

```python
# Monitor optimization effectiveness
monitoring = agent.set_optimization_monitoring({
    "track_token_savings": True,
    "track_cost_savings": True,
    "track_quality_metrics": True,
    "alert_on_degradation": True,
    "quality_threshold": 0.8
})
```

### Testing

```python
# Test optimization before deployment
test_results = agent.test_optimization_rules(
    test_prompts=test_dataset,
    quality_threshold=0.9
)

# {
#   "pass_rate": 0.94,
#   "avg_quality_score": 0.92,
#   "avg_token_reduction": 0.58,
#   "failed_cases": 6
# }
```

---

## 🎯 Next Steps

Now that you understand optimization:

1. **[Learn Routing](routing.md)** - Advanced routing strategies
2. **[Explore Debugging](debugging.md)** - Optimization tracing
3. **[Check Examples](examples.md)** - Optimization in action
4. **[API Reference](api-reference.md)** - Full optimization API

---

*Ready to optimize your LLM usage? Check out the [Examples documentation](examples.md) to see optimization in action!*
