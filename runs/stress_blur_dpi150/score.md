# Score: stress_blur_dpi150 (labels: labels/, 3 repeats)

## Per report (mean over repeats)

| report | rate | rows | correct | critical | wrong_value | wrong_unit | wrong_range | invented_range | invented_row | unpaired | duplicate | miss_rows | dropped_row | null_value | missing_unit | missing_range | review | out_of_order | abnormal_rows | abnormal_critical | failed |
|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|
| 01 | 100.0% | 14 | 14 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 3 | 0 | 0/3 |
| 02 | 100.0% | 16 | 16 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 6 | 0 | 0/3 |
| 03 | 100.0% | 8 | 8 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0/3 |
| 05 | 100.0% | 14 | 14 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 5 | 0 | 0/3 |
| 06 | 100.0% | 12 | 12 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 3 | 0 | 0/3 |
| 11 | 94.4% | 54 | 51 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 3 | 0 | 9 | 0 | 0/3 |

## Headline (per repeat: mean, min, max)

- **Correct-row rate (pooled):** 0.9746 (min 0.9746, max 0.9746)
- **Critical errors:** 0 (min 0, max 0)
- Critical errors on abnormal rows: 0 (min 0, max 0) (of 26 abnormal rows)
- Correct-row rate (mean of reports): 0.9907 (min 0.9907, max 0.9907)
- Miss rows: 0 (min 0, max 0) | Review rows: 3 (min 3, max 3) | Failed reports: 0 (min 0, max 0)
  - wrong_value: 0 (min 0, max 0)
  - wrong_unit: 0 (min 0, max 0)
  - wrong_range: 0 (min 0, max 0)
  - invented_range: 0 (min 0, max 0)
  - invented_row: 0 (min 0, max 0)
  - dropped_row: 0 (min 0, max 0)
  - null_value: 0 (min 0, max 0)
  - missing_unit: 0 (min 0, max 0)
  - missing_range: 0 (min 0, max 0)

## Reliability (separate from accuracy)

- Report runs: 18 | runner attempts: 18 | runner retries: 0 | failed report runs: 0
- Errors seen by the runner: none
- Retries inside the extractor: 0 

## Cost and latency (per report)

- **$ per report:** mean $0.001766, max $0.003897 (18/18 runs with usage)
- $ per 10k reports/day: $17.66
- Tokens per report: prompt 1441 (min 1259, max 2351), output 936.8 (min 439, max 2206), thinking n/a
- Latency of successful call: median 9.7s, max 12.5s; including retries: max 12.5s

## Needs review (repeat 1)

- report_11: ['review_unit_unknown'] label='Aspartate Aminotransferase' pred='Aspartate Aminotransferase'
- report_11: ['review_unit_unknown'] label='Alanine Aminotransferase' pred='Alanine Aminotransferase'
- report_11: ['review_unit_unknown'] label='ALP' pred='ALP'
