# AutoMem Benchmark Results

> Historical note: This report predates the March 10, 2026 LoCoMo evaluator fixes. Temporal and category-5 scoring were corrected later, so these scores and comparisons are not current. See `benchmarks/EXPERIMENT_LOG.md` for current baselines and methodology.

## LoCoMo Benchmark (Long-term Conversational Memory)

**Benchmark Version**: LoCoMo-10 (1,986 questions across 10 conversations)
**Date**: November 8, 2025
**AutoMem Version**: Latest (as of benchmark)

============================================================
📊 FINAL RESULTS
============================================================

🎯 Overall Accuracy: 76.08% (1511/1986)
⏱️ Total Time: 1500.0s
💾 Total Memories Stored: 5882

📈 Category Breakdown:
Single-hop Recall : 59.22% (167/282)
Temporal Understanding : 70.40% (226/321)
Multi-hop Reasoning : 22.92% ( 22/ 96)
Open Domain : 77.41% (651/841)
Complex Reasoning : 99.78% (445/446)

🏆 Comparison with CORE (SOTA):
CORE: 88.24%
AutoMem: 76.08%
📉 AutoMem is 12.16% behind CORE
