---
id: P-UWXMNBBT
type: project
title: Recurrence-ROI (Advantage-Update) Is Internal Learning Signal
created_at: 2026-07-01T13:48:00Z
write_source: auto-extract
trust: medium
recurrence_count: 1
source_file: auto-extract
source_line: 1
source_sha1: 935896b7988f9707e1b02178a6e1eba607ea5940dcdffac52e03320080b8df5c
---

The advantage-update score measures whether a memory helped: `score = with-memory-performance − without-memory-performance`. This is NOT user-facing. It's internal to the kit's memory-improvement loop—it drives which memories get kept, ranked, or consolidated.

**Why:** Earlier analysis confused this across three separate filings (vanity metric, self-cleaning, trust-update). User clarified it's for "kit processes" (internal learning), resolving confusion: ONE feedback signal, ONE purpose.

**How to apply:** When implementing the memory-improvement loop, use advantage-update as the core learning signal. Keep it strictly internal to memory curation; do not expose to users.
