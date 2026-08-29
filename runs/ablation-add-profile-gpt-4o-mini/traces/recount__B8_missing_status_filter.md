# Trajectory — recount — B8_missing_status_filter

`2` model calls (`0` replayed from cassette) · `4` tool calls · `1742` tokens · `$0.00035`

## 1. tool · `run_sql` · execute_under_review · ok

**request**

```sql

            SELECT SUM(p.amount_cents) AS revenue_cents
            FROM orders o
            JOIN payments p ON p.order_id = o.order_id
        
```

**response**

```
revenue_cents
-------------
7301960000   
```

## 2. tool · `profiler.profile` · profile_warehouse · ok

**request**

```json
{
  "tables": [
    "orders",
    "payments"
  ],
  "views": [
    "reviewer",
    "author"
  ]
}
```

**response**

```
MEASURED WAREHOUSE FACTS

Join cardinality (measured, not inferred):
  ! order_items.order_id -> orders.order_id: FANS OUT x2.16 avg, up to x4; 1005 parent keys have >1 child row
  ! orders.customer_id -> customers.customer_id: FANS OUT x3.86 avg, up to x12; 352 parent keys have >1 child row
  ! payments.order_id -> orders.order_id: FANS OUT x1.24 avg, up to x3; 252 parent keys have >1 child row
    refunds.order_id -> orders.order_id: one row per parent (safe to join)

orders: 1500 rows, one row per order_id
  order_id: INTEGER, pk, 1500 distinct
  customer_id: INTEGER, 389 distinct
  order_ts: TEXT, 1493 distinct, range 2026-01-01 02:11:00 .. 2026-03-31 21:27:00
  status: TEXT, NULL in 80 rows (5.3%), 4 distinct
  currency: TEXT, 2 distinct

payments: 1683 rows, one row per payment_id
  payment_id: INTEGER, pk, 1683 distinct
  order_id: INTEGER, 1357 distinct
  amount_cents: INTEGER, 941 distinct
  paid_ts: TEXT, 1672 distinct, range 2026-01-01 03:12:00 .. 2026-05-30 03:21:00
  method: TEXT, 4 distinct
```

## 3. tool · `profiler.format_hints` · value_formats · ok

**request**

```json
{
  "tables": [
    "orders",
    "payments"
  ]
}
```

**response**

```
STORED VALUE FORMATS

  orders.order_ts (TEXT): values are stored like '2026-01-01 02:11:00' through '2026-03-31 21:27:00'
  payments.paid_ts (TEXT): values are stored like '2026-01-01 03:12:00' through '2026-05-30 03:21:00'

Write literals in exactly this format. A differently formatted string compares as text rather than as a time, and silently selects the wrong rows.
```

## 4. model · recompute

`gpt-4o-mini` · live call · 568 in / 83 out · 1.03s

**system**

```
You are a senior analytics engineer. You are handed a
business question and the measured facts about a warehouse, and you write the
query that answers it. You are not reviewing anyone's work: you are deriving the
answer independently.
```

**user**

```
Business question:
What revenue did we capture from completed orders only, in cents?

MEASURED COLUMN FACTS

orders: 1500 rows, one row per order_id
  order_id: INTEGER, pk, 1500 distinct
  customer_id: INTEGER, 389 distinct
  order_ts: TEXT, 1493 distinct, values run '2026-01-01 02:11:00' .. '2026-03-31 21:27:00'
  status: TEXT, NULL in 80 rows (5.3%) -- a predicate on this column must handle NULL explicitly, 4 distinct
  currency: TEXT, 2 distinct

payments: 1683 rows, one row per payment_id
  payment_id: INTEGER, pk, 1683 distinct
  order_id: INTEGER, 1357 distinct
  amount_cents: INTEGER, 941 distinct
  paid_ts: TEXT, 1672 distinct, values run '2026-01-01 03:12:00' .. '2026-05-30 03:21:00'
  method: TEXT, 4 distinct

Match the stored format exactly when you write a literal. The quoted ranges above show how values are actually stored; comparing against a differently formatted string compares text, not time, and silently selects the wrong rows.

STORED VALUE FORMATS

  orders.order_ts (TEXT): values are stored like '2026-01-01 02:11:00' through '2026-03-31 21:27:00'
  payments.paid_ts (TEXT): values are stored like '2026-01-01 03:12:00' through '2026-05-30 03:21:00'

Write literals in exactly this format. A differently formatted string compares as text rather than as a time, and silently selects the wrong rows.

Write a single read-only SQL query that answers this question against this
SQLite warehouse.

Derive it from the question and the measured facts above. Pay attention to the
grain of each measure, to columns that are nullable in practice, and to the
stored format of any value you compare against.

Return exactly these columns, in this order, with these names:
revenue_cents

Reply with one JSON object and nothing else:

{"sql": "a single SELECT, no semicolon", "reasoning": "one sentence on the grain and filters you chose"}
```

**assistant**

```json
{"sql": "SELECT SUM(p.amount_cents) AS revenue_cents FROM orders o JOIN payments p ON o.order_id = p.order_id WHERE o.status IS NOT NULL AND o.status = 'completed'", "reasoning": "I joined the orders and payments tables on order_id, filtered for completed orders by checking that status is not NULL and equals 'completed', and summed the payment amounts in cents."}
```

## 5. tool · `run_sql` · recompute · ok

**request**

```sql
SELECT SUM(p.amount_cents) AS revenue_cents FROM orders o JOIN payments p ON o.order_id = p.order_id WHERE o.status IS NOT NULL AND o.status = 'completed'
```

**response**

```
revenue_cents
-------------
5468920000   
```

## 6. note · probes_disabled

Probe stage disabled for this run; adjudicating from measured facts alone.

## 7. model · adjudicate

`gpt-4o-mini` · live call · 967 in / 124 out · 1.50s

**system**

```
You are a senior analytics engineer signing off on
whether a number can go into a business report. You have executed probes and an
independent recomputation, and you now decide based on what they returned.
```

**user**

```
Business question the analyst asked:
What revenue did we capture from completed orders only, in cents?

SQL under review:
SELECT SUM(p.amount_cents) AS revenue_cents
            FROM orders o
            JOIN payments p ON p.order_id = o.order_id

Result it returned:
revenue_cents
-------------
7301960000   

MEASURED WAREHOUSE FACTS

Join cardinality (measured, not inferred):
  ! order_items.order_id -> orders.order_id: FANS OUT x2.16 avg, up to x4; 1005 parent keys have >1 child row
  ! orders.customer_id -> customers.customer_id: FANS OUT x3.86 avg, up to x12; 352 parent keys have >1 child row
  ! payments.order_id -> orders.order_id: FANS OUT x1.24 avg, up to x3; 252 parent keys have >1 child row
    refunds.order_id -> orders.order_id: one row per parent (safe to join)

orders: 1500 rows, one row per order_id
  order_id: INTEGER, pk, 1500 distinct
  customer_id: INTEGER, 389 distinct
  order_ts: TEXT, 1493 distinct, range 2026-01-01 02:11:00 .. 2026-03-31 21:27:00
  status: TEXT, NULL in 80 rows (5.3%), 4 distinct
  currency: TEXT, 2 distinct

payments: 1683 rows, one row per payment_id
  payment_id: INTEGER, pk, 1683 distinct
  order_id: INTEGER, 1357 distinct
  amount_cents: INTEGER, 941 distinct
  paid_ts: TEXT, 1672 distinct, range 2026-01-01 03:12:00 .. 2026-05-30 03:21:00
  method: TEXT, 4 distinct

Probes you designed, and what executing them actually returned:
(no probes were executed)

An independent recomputation was derived from the business question alone, without seeing the query under review, then executed:

  sql: SELECT SUM(p.amount_cents) AS revenue_cents FROM orders o JOIN payments p ON o.order_id = p.order_id WHERE o.status IS NOT NULL AND o.status = 'completed'
  returned:
    revenue_cents
    -------------
    5468920000   

  the query under review returned:
    revenue_cents
    -------------
    7301960000   

Decide the verdict from what was executed, not from how the SQL looks.

* The recomputation above is the strongest evidence available. If it returns a
  different number from the query under review, the two disagree and the
  reported number cannot be trusted. If it returns the same number, two
  independent derivations agree.
* Judge against the business question. Joining to a finer grain is a bug when
  the requested metric is coarser, and correct when the metric genuinely lives
  at that finer grain.
* If you answer BUG, corrected_sql is mandatory and will be executed.

Reply with one JSON object and nothing else:

{
  "verdict": "CLEAN" | "BUG" | "ESCALATE",
  "bug_type": one of ["fanout_join", "null_swallowing_predicate", "left_join_degraded_to_inner", "date_range_truncation", "timezone_day_boundary", "mixed_unit_aggregation", "missing_filter", "wrong_aggregation_grain", "other"] or null,
  "confidence": number between 0 and 1,
  "explanation": "at most 3 sentences, concrete, naming the tables involved",
  "corrected_sql": "a single SELECT that answers the business question, or null"
}

Verdict meanings:
  CLEAN     - the query correctly answers the business question.
  BUG       - the query runs but returns a number that does not answer the
              business question. Set bug_type and corrected_sql.
  ESCALATE  - answering needs a business decision you cannot make from the
              schema and data alone. Use this instead of guessing.

Judge the query against the business question, not against style. A join to a
finer grain is a bug when the metric is coarser, and correct when the metric
actually lives at that finer grain.
```

**assistant**

```json
{
  "verdict": "BUG",
  "bug_type": "missing_filter",
  "confidence": 0.95,
  "explanation": "The query under review does not filter for completed orders, which is necessary to accurately capture revenue from completed orders only. The independent recomputation correctly includes this filter, resulting in a significantly different revenue amount from the query under review.",
  "corrected_sql": "SELECT SUM(p.amount_cents) AS revenue_cents FROM orders o JOIN payments p ON o.order_id = p.order_id WHERE o.status IS NOT NULL AND o.status = 'completed'"
}
```

## 8. gate · verification_gate

**BUG** — an independently derived query returns a different number, demonstrating the discrepancy

```json
{
  "reported": "revenue_cents\n-------------\n7301960000   ",
  "recomputed": "revenue_cents\n-------------\n5468920000   "
}
```
