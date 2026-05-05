# Comprehensive F2 contract test suite — testing log (2026-05-05)

Goal: replace the legacy parity replay machinery with a comprehensive
spec-driven test suite that exercises every aspect of
`search-api/openapi.yaml` (POST `/{collection}/_search`) against the
real catalog loaded into Milvus (`articles_v6` + `offers_v6`).

## Working facts about the loaded catalog

Captured 2026-05-05 from a live `pymilvus` scan of the loaded
collections. These pin known-good values for deterministic test
scenarios.

### Collections

| Collection      | Rows         | Notes |
| --------------- | ------------ | ----- |
| `articles_v6`   | 982 753      | Article-side: name, manufacturerName, category_l1..l5, eclass5/7, s2class, per-currency price min/max, BM25 codes, dense embedding |
| `offers_v6`     | 1 963 490    | Offer-side: vendor_id, catalog_version_id, prices JSON, delivery_time, features array, core marker arrays, relationship arrays, price_list_ids, currencies array, per-currency price min/max |
| `offers_codes`  | 158 269 705  | BM25 sparse codes for legacy `_search_v0` path |

### Known-good values to drive tests

* **Vendor IDs** (offer-side): `6a67b8b5-9b7c-47f0-92d5-1dfd8812a505`,
  `216c5d41-b64a-42f1-b084-d7e3419b2219`, `e22f1ac6-14bc-4287-ab0d-1f34c1780f2e`,
  `01054f55-c50c-452b-8822-ee11be4788c9`
* **Catalog version IDs**: `afe615ec-beee-4283-a530-24519843b399`,
  `830c5984-51a4-44e9-a56a-a2e77fbd6568`, `a73870cc-1844-4c17-a55c-998b1f017949`
* **Price list IDs**: `0330f11c-9d00-4a58-9978-76e4d71fed80` and many more
* **Manufacturers** (article-side): `Würth`, `GARANT`, `SMC`, `TOOLCRAFT`, `Siemens`
* **Category L1**: `Zerspanung`, `Elektromaterial`, `Verbindungselemente`
* **EClass5 codes** (int): 21010101, 23110101, 27260701, 27269134, 32169090
* **Currencies present in `currencies` array**: `eur` (dominant), `chf`
* **Currency-code columns**: `eur`, `chf`, `huf`, `pln`, `gbp`, `czk`, `cny`
* **Delivery time values**: 1..32 days observed
* **EUR price spread**: 0.10 .. ~1929 (a sentinel `FLT_MAX` shows up for
  rows with no eur price — must exclude when sampling bounds)
* **Feature value examples** (offer-side, format `key=value`):
  `Ursprungsland=IT`, `Eigenschaften=chemikalienbeständig`
* **Free-text query candidates**: `schraube`, `bohrer`, `drill`,
  `siemens`, `kabel`, `dichtung`, `airplane` (use ones with known hits
  to make hit-count assertions stable)

### Pre-existing services state at start of session

* Milvus + minio + etcd up at `localhost:19530`
* Redis up at `localhost:6379`
* Observability (grafana/prometheus/caddy) up
* search-api / acl / playground-app: **not** running — tests run the
  FastAPI app in-process via `TestClient`, with `EMBED_URL=http://embed.invalid`
  to force the no-query browse path or to fail loud on the dense leg
  unless we explicitly mock the embedder.

## Run log

### Iteration 1 — `nullable: true` on `$ref` fields

Suite stopped at `TestValidator.test_envelope_with_articles_and_summaries`
with the error:

```
- ['summaries', 'categoriesSummary']: None is not of type 'object'
- ['summaries', 'eClass5Categories']:  None is not of type 'object'
- ['summaries', 'eClass7Categories']:  None is not of type 'object'
- ['summaries', 's2ClassCategories']:  None is not of type 'object'
```

**Root cause:** OpenAPI 3.0 lets you write `{ $ref: '…/X', nullable: true }`
to mean "X or null". My `_openapi_to_jsonschema` converter only handles
`nullable: true` when the schema has a literal `type:` field — it
doesn't expand the `$ref + nullable` shape into `anyOf: [$ref, {type:null}]`.

**Fix:** in `_openapi_to_jsonschema.walk()`, when a node has both
`$ref` and `nullable: true`, emit `anyOf: [{ $ref: <ref> }, { type:
"null" }]` instead of leaving the bare `$ref` alone.

### Iteration 2 — `Metadata.recallClipped` / `hitCountClipped` missing from spec

```
- ['metadata']: Additional properties are not allowed
  ('hitCountClipped', 'recallClipped' were unexpected)
```

**Root cause:** The `Metadata` pydantic model in
`search-api/models.py` declares `recallClipped: bool = false` and
`hitCountClipped: bool = false` — surfaced by F4/F9 and emitted on
every response. The OpenAPI YAML's `Metadata` schema never grew the
two fields. Real spec drift — the OpenAPI is documented (in `main.py`
header) as the contract source of truth.

**Fix:** add both fields to `components.schemas.Metadata` in
`search-api/openapi.yaml`, with the same description text the
pydantic model carries.

### Iteration 3 — `queryString` is the legacy ACL field name; F2 uses `query`

```
{"detail":[{"type":"extra_forbidden","loc":["body","queryString"], …}]}
```

**Root cause:** test bug — I copied a legacy ACL request shape that
uses `queryString`. The F2 ftsearch contract uses `query`.

**Fix:** rename `queryString` → `query` in the test bodies.

### Iteration 4 — `pageSize` is a query param, not a body field

Test sent `pageSize` inside the JSON body. F2 contract puts pagination
exclusively on the query string (parameters block). Fixed by moving
to `?pageSize=…`.

### Iteration 5 — green at 88 tests

After the spec fix and the two test bugs, the suite was 88-green.
Subsequent commits added five more classes (auth alternatives,
negative bodies, behaviour, summary content, deeper summaries,
minimal-body). Stable at 111 passing.

## State of adjacent suites

Sanity-ran the broader test sweep once the F2 file went green. The
following pre-existing failures are **unrelated** to F2 and predate
this work:

* `test_offers_collection_schema` — depends on a Milvus alias
  `offers_v_alias` that no longer exists in the running cluster.
* `test_duckdb_*`, `test_index_*`, `test_projection`, `test_tei_cache`
  — depend on tooling/parquet fixtures unrelated to the F2 path.
* `test_catalog_benchmark` — pre-existing tokenizer-stub bug in
  `infer.py`.

F2/ACL-adjacent suites (search-api contract, search-dedup integration,
all ACL acceptance + skeleton + integration tests + the new F2 file)
all pass: 192 passed, 27 skipped, 0 failed.

### Iteration 6 — `metadata.term` divergence between dedup and legacy paths

```
term '' != expected None for query None
```

**Root cause:** main.py wires `term` differently in the two F2 paths:
- legacy single-collection: `term=body.query` (None propagates).
- F9 dedup-topology (the path articles_v6/offers_v6 use):
  `term=body.query or ""` (None becomes "").

Spec declares `term: { type: string, nullable: true }`, so both wire-
shapes are valid, but the two paths disagree on what they emit for
the same input. Real bug: the dedup path silently coerces null → "".

**Fix:** align dedup path with legacy + spec — drop the `or ""` so
None propagates. Tested implicitly by the F2 suite via the
term-echoes-query-text test.

## Coverage summary at 129-passing checkpoint

`tests/test_f2_contract_against_catalog.py` covers, against the live
`articles_v6` + `offers_v6` corpus:

* OpenAPI document health: 3.x meta-validation; every `$ref`
  resolves; every (path, verb, status, media) entry references a
  declared schema; pydantic models stay in lockstep with the YAML
  for `SearchRequest`, `Metadata`, `Summaries`, `Article`,
  `SearchMode`, `SummaryKind`, `EClassVersion`.
* Validator self-test (3 cases).
* Path/query parameters: collection, page (default + custom +
  rejection of 0), pageSize (0, 500, 501, default), sort (every
  field × direction, multi-key first-key-only acceptance, unknown
  field/direction rejection), missing-collection 404.
* Body validation: every required field rejection, every sub-schema
  `additionalProperties=false` rejection, currency pattern, search
  mode enum, search-articles-by/explain (legacy fields explicitly
  rejected), nested `requiredFeatures`/`blockedEClassGroups`
  /`selectedArticleSources` extras, summaries enum membership.
* searchMode envelope: HITS_ONLY (summaries suppressed even when
  requested), SUMMARIES_ONLY (no articles), BOTH (both populated).
* Filters (each tested): vendorIdsFilter (with offer-ownership
  assertion), articleIdsFilter (round-trips a real id), manufacturer
  filter, eClassesFilter, currentEClass{5,7,S2}Code, max delivery,
  required features, blocked eclass vendors, core sortiment, core
  articles vendors, closed marketplace toggle (CV scope swap),
  s2ClassForProductCategories, eClassesAggregations.
* Relationship filters: accessoriesFor, sparePartsFor, similarTo.
* Price filter: min+max, only-max, only-min, narrowing assertion,
  invalid currency rejection, missing currencyCode rejection.
* Sort ordering: articleId asc/desc actually sorted; relevance sort
  returns descending scores when query is set; multi-key first-key
  only.
* Pagination: pageCount math, no overlap between adjacent pages,
  page=9999 returns empty, idempotence on identical requests.
* Summaries: every SummaryKind yields a valid envelope; vendor and
  manufacturer buckets contain the filtered values; bucket counts
  do not exceed total hitCount; categoriesSummary echoes
  currentCategoryPathElements; eClass5Categories shape; pricesSummary
  currency code pattern + min ≤ max; featureSummaries parent ≥ max
  child count.
* Auth: 401 + Error envelope when API_KEY is set and missing/wrong;
  both `Authorization: ApiKey` and `X-API-Key` accepted; /metrics
  and /openapi.yaml bypass auth; /openapi.json equals /openapi.yaml.
* Concurrency: 503 + `Retry-After: 1` + Error envelope when the gate
  is saturated.
* Behaviour: high-volume vendor → hits>0; unknown vendor / unknown
  manufacturer → 0; HITCOUNT_CAP=1 with article-side filter clips
  hitCount and sets hitCountClipped=true; Article.score is null in
  browse and numeric in query path; Unicode (`größe`) and long (~1.8KB)
  query strings round-trip.
* Term echo: schraube → "schraube"; "" → ""; null/omitted → null.
* Minimal valid body (only the spec's three required fields).

### Fixes shipped while building the suite

1. `Metadata.recallClipped` and `Metadata.hitCountClipped` were
   emitted by the implementation but missing from
   `search-api/openapi.yaml`. Added to the spec.
2. `_search_dedup` emitted `metadata.term = ""` for `query=null`
   while the legacy single-collection path emits `null`. The dedup
   path was wrong — corrected to match the spec (`term: nullable`)
   and the legacy path.
3. `routing._to_hits` documented (in its docstring) that
   non-relevance sort emits `score=None` per spec §3, but the code
   emitted `score=0.0`. The wire was misleading: a hit with no
   ranking carried the same value as a hit ranked at the bottom of
   the relevance distribution. Fixed `Hit.score` to be
   `float | None` and corrected the non-relevance branch to pass
   `None`. Surfaced when checking the live HTTP response.

## Final state at suite milestone

* `tests/test_f2_contract_against_catalog.py`: **176 passing, 5
  consecutive runs identical** (~12s wall time per run).
* Adjacent F2 + ACL suites (search-api contract, search-dedup
  integration, ACL acceptance/skeleton/integration/error/resilience,
  filter integration): **255+ passing, 60 skipped, 0 failed**. The
  skips are environment-gated paths (missing TEI, missing parquet
  fixtures); no regressions from the dedup-path `term` fix.
* Unrelated repo-wide failures (`test_duckdb_*`, `test_index_*`,
  `test_projection`, `test_tei_cache`, `test_offers_collection_schema
  alias tests`, `test_catalog_benchmark`) all pre-existed this work
  and stem from missing parquet fixtures, missing milvus aliases,
  or a tokenizer-stub bug in `infer.py`.

## Test-class index

| Class | What it covers |
| --- | --- |
| `TestValidator` | Validator self-test (envelope/ extra/ required/ count rejection) |
| `TestParameters` | page/pageSize/sort path+query parameters |
| `TestBodyValidation` | Required-field and per-field rejections |
| `TestSearchModes` | HITS_ONLY/SUMMARIES_ONLY/BOTH envelope shapes |
| `TestFilters` | Each scalar filter atom from spec §4.3 |
| `TestRelationships` | accessoriesFor / sparePartsFor / similarTo |
| `TestPriceFilter` | min/max/only-min/only-max/narrowing/invalid currency |
| `TestSortOrderings` | articleId/relevance/multi-key/explicit-sort beats relevance |
| `TestPagination` | pageCount math, page overlap, summary stability across pages |
| `TestSummaries` | Each SummaryKind yields a valid envelope |
| `TestAuthAndConcurrency` | API_KEY 401 + 503 gate + HITCOUNT_CAP |
| `TestBehaviour` | Filter narrowing assertions on the live catalog |
| `TestFreeTextQuery` | query body field, term echo, Unicode, long strings |
| `TestArticleIdsFilter` | Real offer-id round-trips |
| `TestPaginationEdges` | pageSize=500 boundary, page=9999 |
| `TestSummaryContent` | Summary buckets contain filtered values, count caps |
| `TestOpenAPIDocument` | Spec/impl parity on every schema, examples valid, $refs resolve |
| `TestNegativeBodies` | Per-sub-schema additional-properties rejection |
| `TestAuthHeaderAlternatives` | Both auth header forms; metrics/openapi public bypass |
| `TestPageSizeZero` | pageSize=0 keeps real hitCount |
| `TestMinimalBody` | Request with only the spec-required fields |
| `TestDeeperSummaries` | Per-summary content invariants |

---

## ACL OpenAPI Contract Suite (`test_acl_openapi_catalog.py`)

### Run: 89 passed, 0 failed (2.5s)

Comprehensive end-to-end tests of `acl/openapi.yaml` against the real
loaded catalog, hitting ACL on 8081 -> search-api on 8001 -> Milvus.

| Category | Count | Notes |
|---|---|---|
| Health & OpenAPI | 2 | /healthz, /openapi.yaml serving |
| Response Schema | 8 | Top-level keys, article shape, metadata, no extra fields |
| Article ID Format | 2 | Colon-separated, base64 decodable |
| Search Modes | 3 | HITS_ONLY, SUMMARIES_ONLY, BOTH |
| Pagination | 6 | page/pageSize, beyond-range, zero, consistency, stability |
| Sorting | 8 | articleId/name/price asc/desc, invalid field/direction |
| Explain (section 2.2) | 2 | explain=true stubs "N/A", false omits |
| Filters | 15 | vendor, manufacturer, deliveryTime, closedMarketplace, multi-CV, empty scope, nonexistent CV, articleIds, accessories, similar_to, eclass, features, priceFilter |
| Text Search | 5 | query with results, null browse, nonsense query, query+sort, term echo |
| Summaries | 14 | All SummaryKinds, shape validation, aggregations |
| Currency | 2 | EUR, CHF with CHF catalog |
| Validation | 12 | Missing fields, error envelope, all legacy enums rejected |
| ACL Contract | 6 | Dropped fields accepted, blocked eclass, category path |
| Core Sortiment | 2 | coreSortimentOnly, coreArticlesVendorsFilter |
| Stability | 2 | Idempotent hitCount, deterministic ordering |

### Findings

**Price sort requires sourcePriceListIds**: `resolve_price()` returns
`None` when `sourcePriceListIds` is empty. With `sort=price`,
`pick_representative()` drops all offers. Result: `hitCount=113,
articles=[]` — metadata counts filter-scoped articles but materialisation
drops them all.

**hitCount on zero-match queries**: When BM25+dense finds zero ranked
articles, Path B hitCount still reflects the full filter-scoped count.

**Dense search always returns neighbors**: Nonsense queries still return
articles because HNSW always finds nearest neighbors.

**ACL collection path naming confusion**: The ACL's
`MILVUS_ARTICLES_COLLECTION` env var is used as the URL path collection
for ftsearch calls. In dedup topology, this must be the *offers*
collection. Same env var name means different things in the two services.

### Iteration 2: review-driven improvements (89 -> 100 tests)

Applied 15 review findings:
- Sort tests verify asc/desc produce different orders
- Filter tests compare against unfiltered baselines
- articleIdsFilter asserts exclusivity
- Added missing spec features: sparePartsForArticleNumber, currentEClass7Code,
  currentS2ClassCode, PLATFORM_CATEGORIES, empty queryString, pageSize=500
- Sub-schema additionalProperties: false tested for selectedArticleSources,
  priceFilter, FeatureFilter

### Iteration 3: behavioral cross-checks (100 -> 107 tests)

Added semantic/behavioral tests beyond shape validation:
- Vendor summary count equals hitCount
- Price filter narrows results (strict `<`)
- Delivery time filter narrows results (strict `<`)
- Combined filters are AND-composed
- Price sort without sourcePriceListIds returns zero articles but nonzero hitCount
- SUMMARIES_ONLY hitCount matches BOTH hitCount
- Page beyond range has correct nonzero metadata

### Red-team v1: 41 tests exposing 9 ACL validation bugs (all fixed)

Launched adversarial red-team subagent to find tests that fail. Found 9 bug categories:

1. **String→boolean coercion** (18 tests): `explain="yes"` accepted — Pydantic lax mode
2. **Int→boolean coercion** (4 tests): `explain=0` accepted
3. **Bool→integer coercion** (2 tests): `maxDeliveryTime=True` accepted
4. **String→integer coercion** (5 tests): `maxDeliveryTime="0"` accepted
5. **Bool in priceFilter.min** (1 test): `priceFilter.min=True` accepted
6. **Float→integer coercion** (1 test): `currentEClass5Code=23110103.0` accepted
7. **Snake-case field names** (4 tests): `search_mode` accepted due to `populate_by_name=True`
8. **UUID format not validated** (4 tests): `vendorIdsFilter=["not-a-uuid"]` accepted
9. **Sort validation leak** (2 tests): invalid sort forwarded to ftsearch, error leaks internals

**Root-cause fix**: `StrictBool`/`StrictInt` on all boolean/integer fields, removed
`populate_by_name=True`, `UuidStr` regex type for UUID fields, sort regex
validation in ACL before forwarding.

### Red-team v2: 13 tests exposing 6 more ACL bugs (all fixed)

1. **404 error envelope violation** (2 tests): unknown paths returned FastAPI's
   `{"detail":"Not Found"}` instead of spec `{message, details, timestamp}`
2. **405 error envelope violation** (5 tests): wrong HTTP methods returned
   `{"detail":"Method Not Allowed"}` — Starlette router bypass
3. **FeatureFilter.values not required** (1 test): spec says `required: [name, values]`
   but model had `default_factory=list`
4. **EClassesAggregation.eClasses not required** (1 test): same pattern
5. **BlockedEClassVendorsFilter.blockedEClassGroups not required** (1 test): same pattern
6. **Upstream 422 status leak** (3 tests): ftsearch 422 forwarded verbatim (not in spec),
   error message contained "ftsearch", details leaked raw upstream payload

**Root-cause fix**: `StarletteHTTPException` handler for 404/405, removed
`default_factory` from required fields, mapped upstream status codes to spec-defined
codes (4xx→400, 5xx→500), sanitized error messages.

**Total: 167 tests (113 main + 41 red-team v1 + 13 red-team v2), all passing.**

### Red-team round 2: 6 parallel agents (93 new tests)

Launched 6 specialized red-team agents simultaneously:

#### Response mapper fixes (3 bugs fixed)
1. **eClassesAggregations rename missing**: ftsearch returns `{id, count}`,
   legacy spec requires `{name, count}` — 3 agents independently found this
2. **Metadata field leak**: denylist only stripped 2 keys; changed to allowlist
   of the 5 spec-defined keys
3. **Summaries field leak**: same pattern; allowlist of 9 spec-defined keys
4. **pageCount < 1 for empty results**: legacy always returns `max(1, totalPages)`;
   ACL now clamps

#### Next-gen legacy caller analysis (15 findings)
Key findings from reading `../next-gen/article/search/` Java/Kotlin code:
- **articleId format**: ftsearch returns 3-part `vendorId:b64num:cvId`, legacy
  expects 2-part `friendlyId:b64num`. **OPEN BUG** — ftsearch/indexer issue.
- **pageCount >= 1**: fixed (see above)
- **searchArticlesBy**: only `STANDARD` accepted, but portal-bff sends `ALL_ATTRIBUTES`
  via mapper — routing must filter before ACL
- **Price filter minor units**: prices are cents on the wire; ACL must match
- **PLATFORM_CATEGORIES**: never sent on wire (mapped to ECLASS5SET in portal-bff)
- **Error wrapping**: portal-bff wraps ALL errors as `SearchServiceUnavailableException`,
  can't distinguish 400 from 500

#### Security findings (20 tests, 10 categories)
High severity:
- No request body size limit (20MB accepted)
- No maxItems on filter arrays (100k UUIDs accepted)
- No maxLength on queryString (1MB accepted)
- No rate limiting

Medium severity:
- Prometheus /metrics on app port (should be 9090)
- Swagger UI/ReDoc exposed
- Error messages leak "ftsearch unreachable" + upstream status codes

#### ftsearch/search-api edge cases (25 tests, 4 bugs)
- **Page overflow crash**: `page*pageSize > 16384` → unhandled 500 or connection reset
- **hitCount lies with price sort**: hitCount=113, articles=[] when no prices resolve
- **Whitespace-only query**: `query="   "` → `term="   "` instead of null
- **Category depth > 5 silently ignored**: no error, returns unfiltered results

#### Data integrity (13 tests, 1 warning)
All clean except: 95% of `relationship_accessory_for` targets don't resolve
(incomplete catalog load, not a runtime issue).

**Total: 260 tests across 10 suites. 259 pass, 1 known failure (articleId format).**

### Open issues (not yet fixed)

| Issue | Severity | Owner | Notes |
|-------|----------|-------|-------|
| articleId 3-part format | HIGH | ftsearch/indexer | Offer `id` indexed as `vendorId:b64num:cvId`, legacy expects 2 parts |
| Page overflow crash (page*pageSize > 16384) | HIGH | search-api | Needs rank_limit clamp or page upper bound |
| No request body size limit | MEDIUM | ACL | Add middleware or proxy limit |
| No rate limiting | MEDIUM | ACL/infra | Add rate limiter or rely on upstream proxy |
| hitCount lies with price sort | MEDIUM | search-api | hitCount computed before price-drop filtering |
| /metrics on app port | LOW | ACL | Should be on separate port 9090 per spec |
| Swagger UI exposed | LOW | ACL | Disable in production |
