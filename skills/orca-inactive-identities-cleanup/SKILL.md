---
name: orca-inactive-identities-cleanup
description: Inactive-identity cleanup - finds inactive identities (users, groups, and non-human identities) across an account, business unit, or tag in every cloud provider Orca supports (AWS, Azure incl. Entra ID, GCP incl. Google Workspace, Alibaba Cloud, OCI, Tencent Cloud), ranks them by identity risk score (highest risk first), and drives remediation through a non-destructive path (disable) or a destructive path (delete) that always requires explicit confirmation. Asks for the inactivity time frame (e.g. last 60 days) when the user hasn't given one. Use when the user wants to clean up inactive or dormant identities, offboard unused users or service accounts, delete stale groups, or shrink the identity attack surface (e.g. "clean up inactive identities", "find dormant users", "disable unused service accounts").
trigger: When the user asks to "clean up inactive identities", "find dormant users", "which identities are unused", "delete stale accounts", "disable inactive service accounts", "remove identities nobody uses", "identity cleanup", "offboard stale identities", or passes an account / business unit / tag for an inactive-identity sweep.
---

# Orca Inactive-Identity Cleanup Skill

Answers the question: **"Which of our identities are dead weight, and how do we safely disable or delete them?"**

Every identity that exists but is never used is pure attack surface: it can be phished, its keys can leak, and nobody notices when it starts doing things. This skill sweeps an account or business unit for inactive **users, groups, and non-human identities (NHIs)**, ranks them by identity risk score, and walks the user through cleanup with a **non-destructive path (disable)** and a **destructive path (delete)** that is always gated behind explicit confirmation.

**The core signal:** every identity Orca covers carries a pre-computed activity verdict on the asset itself: `LastActiveTime` (when it last did anything) and `IsIdentityActive` (Orca's uniform **90-day** activity convention, computed at scan time). This holds across **all six supported providers: AWS, Azure (incl. Entra ID), GCP (incl. Google Workspace), Alibaba Cloud, OCI, and Tencent Cloud**. Read the verdict off the asset first; CDR log replay is corroboration, never the primary source.

On top of that, three providers carry extra unused-access evidence for the grant side:
- **AWS:** `AccessKeyNLastUsedDate` per key, `PermissionUsage` scalar, Access Analyzer unused-access findings.
- **Azure:** an unused-access `Recommendation` inline on the `AzureIamRoleAssignment` asset.
- **GCP:** `Recommendation` + `LastUsageTime` on the `GcpIamPolicyBindingRecommendation` model (feature-flag gated in some tenants; fall back to the identity's own timestamps when absent).

## Usage

```
/orca-inactive-identities-cleanup 123456789012                 # one cloud account
/orca-inactive-identities-cleanup "Production"                 # a business unit
/orca-inactive-identities-cleanup 123456789012 --inactive 60d  # custom time frame (skips the question)
/orca-inactive-identities-cleanup 123456789012 --only nhis     # bucket: users | groups | nhis
/orca-inactive-identities-cleanup --tag env=prod               # scope by tag (instead of account / BU)
/orca-inactive-identities-cleanup 123456789012 --action disable  # pre-select the non-destructive path
```

Or natural language:
- "clean up inactive identities in acme-production"
- "which users haven't been active in the last 60 days?"
- "find groups nobody uses and get rid of them"
- "disable the dormant service accounts in the Production BU"
- "any stale RAM users in our Alibaba account?"

## Processing Logic

### Step 1: Resolve scope and time frame

1. **Resolve scope first (ask if not given).** The skill needs a scope before anything else. Accept any one of three:
   - **Account id** used directly.
   - **Business unit**: `get_business_units_data` returns the BU's saved filter (accounts, providers, tags), not a ready-made account list, so derive the member accounts from that filter before sweeping. The response is **large, unpaginated, and has no name filter** (100K+ chars, routinely over the token limit and dumped to a file); grep it for the BU name with a **narrow context window** (~60-120 chars each side, wider matches can be silently truncated by the harness) instead of reading the whole blob.
   - **Tag** (`--tag key=value`, repeatable, or "identities tagged env=prod" in words): sweep every identity carrying the given tag(s), across accounts. Express the tag in the Step 2 `discovery_search` query; if the query can't honor it, post-filter retrieved results on the identity's tag fields (`OrcaTags` / `Tags` / `ModelTags`). A tag scope is bounded by the tag, not the whole org, but it can still match a lot, so the large-account handling in Step 4 / the Edge Cases applies.

   **Disambiguating an unclear scope, in this order:** an all-digits string is an **account id**; otherwise check **business-unit names** first (via `get_business_units_data`) before assuming a tag; treat it as a **tag** only if it's `key=value` or the user said "tag". Guessing a tag first wastes calls, a non-existent tag field returns a 400. **If the user gave none of the three, ask** which account, business unit, or tag to sweep (offer to list the visible BUs) and wait. Never sweep a whole org by default. A tag may also be combined with an account/BU to narrow further, but on its own it is a valid scope.

   **Confirm scope size before sweeping.** Once resolved, if the scope expands to **more than 3 accounts or spans more than 2 cloud providers**, show the breakdown (accounts, providers, rough count from `total_items`) and confirm how to prioritize before sweeping. A named BU is often bigger than the user expects, and "never sweep a whole org" doesn't cover "this BU is larger than you think".
2. **Resolve the time frame (ask if not given), once scope is known.** If the user did not specify an inactivity window (via `--inactive Nd` or in their phrasing, e.g. "last 60 days"), ask:

   > *"What inactivity window should I use? **90 days** is Orca's built-in convention (recommended); common alternatives are 30, 60, or 180 days. You can also give me a custom one."*

   - **Default 90d** maps directly onto the pre-computed `IsIdentityActive: false` verdict (the strongest, scan-time signal).
   - **Any positive window is accepted** (30d, 60d, 180d, 365d, and so on, there is no fixed list). It is evaluated by comparing the asset's `LastActiveTime` against the cutoff, and `LastActiveTime` reaches back years, so long windows work fine. A shorter window (e.g. 30d) flags more identities but with more false positives (vacations, quarterly jobs); a longer one (180d+) is more conservative. State this trade-off in the output. The only thing a custom window cannot decide is an identity with **no `LastActiveTime` at all** (see the no-activity-fields edge case), which stays in the "no signal" bucket regardless of window.
   - Never re-ask on drill-downs or follow-up actions in the same session; the chosen window sticks until the user changes it.

### Step 2: Enumerate identities

**Primary path: `discovery_search` (if enabled).** Query identities with `IsIdentityActive = false` (or fetch and post-filter on `LastActiveTime` for custom windows) across:

> **Don't assume one query returns every identity.** `discovery_search` returns a bounded, risk-ordered result set (read `total_items` for the true count and the result's `app_url` for the full list in the Orca app). A small account comes back whole; a large one (hundreds to ~10k) does not, and that is fine for a risk-first cleanup: retrieve the highest-risk inactive identities (narrow by risk band or provider only if the account is large enough to need it), act on that top slice, and report `total_items` as the real total. Rank within what you retrieved and call it a best-effort ordering of the highest-risk slice, not a global sort of all N. This holds regardless of the current result limit, if the surface later paginates or raises the cap, just retrieve more; the approach is unchanged. Enumerate across:

| Provider | Users | Groups | NHIs / roles |
|----------|-------|--------|--------------|
| AWS | `AwsUser`, `AwsSsoUser` | `AwsIamGroup`, `AwsSsoGroup` | `AwsIamRole`, `AwsSsoPermissionSet` |
| Azure / Entra ID | `AzureUser` | `AzureGroup` | `AzureServicePrincipal` (incl. managed identities), `AzureIamRoleAssignment` for the grant side |
| GCP / Google Workspace | `GcpUser` (Workspace users appear here when the integration is on) | `GcpGroup` | `GcpIamServiceAccount` (+ `GcpIamServiceAccountKey`), `GcpIamPolicyBindingRecommendation` for the grant side |
| Alibaba Cloud | `AliCloudUser` | `AliCloudRamGroup` | `AliCloudRamRole` |
| OCI | `OciUser` | `OciIamGroup`, `OciIamDynamicGroup` | dynamic groups act as the workload-identity primitive |
| Tencent Cloud | `TencentCloudUser` | `TencentCloudCamGroup` | `TencentCloudCamRole` |

**Fallbacks**, in order (`discovery_search` may return `Feature is not enabled`, and it can also fail transiently with 5xx errors while the asset and alert surfaces keep working; fall back on either signal):

1. **Alert-anchored enumeration.** Orca ships built-in inactive-identity alert rules; every alert of these types marks an inactive identity, so `get_alerts_with_similar_alert_type` on them rebuilds the inventory. Machine alert types (pass these exact strings):

   | Provider | Inactive users | Inactive groups | Inactive NHIs / roles |
   |----------|----------------|-----------------|------------------------|
   | AWS | `aws_inactive_user` | `aws_unused_groups`, `aws_inactive_group_with_inactive_users` | `aws_iam_old_role_without_policy`, `aws_iam_old_role_with_policy`, `aws_unused_external_identity_role` |
   | Azure | `azure_inactive_user` | `azure_inactive_group_without_users`, `azure_inactive_group_with_inactive_identities` | `azure_inactive_service_principal` |
   | GCP | `google_workspace_inactive_user` (note: not `gcp_inactive_user`) | `google_inactive_group_with_inactive_users` | `gcp_inactive_service_account` |
   | AliCloud | `alicloud_inactive_user`, `alicloud_unused_user_with_console_logon` | `alicloud_inactive_group_without_users`, `alicloud_inactive_group_with_inactive_users` | no role rule |
   | OCI | `oci_inactive_user` | `oci_inactive_group_without_users`, `oci_inactive_group_with_inactive_users` | no role rule |
   | Tencent | none | none | none |

   Unused-credential types (`aws_unused_aws_credentials`, `aws_credentials_older_than_90_days`, `oci_iam_credentials_unused_for_45_days`, `tencent_user_access_key_not_rotated_90_days`) corroborate and partially cover the gaps.

   Each returned alert embeds the identity asset, its `LastActiveTime`/`CreationTime`, attached policies, and Orca's own `RemediationCli` / `RemediationConsole` steps; reuse those remediation steps when generating artifacts for the less-battle-tested providers (Alibaba, OCI, Tencent).

   **Caveats of this path:** the rules bake in Orca's 90d convention, so a custom window can't be honored here; dismissed/suppressed alerts hide their identities; Tencent has no inactive-identity rules and only AWS has role-inactivity rules. It also returns a **small, unpaginated page** (`total_items` far exceeds the handful of rows returned, e.g. 63 total but 5 returned) and isn't scoped per tenant, so it's a **spot-check, not complete enumeration** in multi-tenant orgs. State that the inventory is "identities Orca currently alerts on" and cover the gaps with path 3.
2. `get_linked_entities_mapping` on key compute assets to walk to workload identities (instance to instance profile to role).
3. `get_asset_by_name` per identity or name pattern, reading `IsIdentityActive` / `LastActiveTime` off each asset (works whenever the serving layer is up, including when discovery is down).

**Classify each identity** into the three buckets this skill acts on:
- **Human users** (console password, MFA, interactive sessions).
- **Groups** (all six providers have group models).
- **NHIs** (roles, service accounts, service principals and managed identities, plus service-account-style users: password disabled, an active access key, API-only usage).

> **Model-type caveat:** `get_asset_by_name` / `get_asset_by_id` reject unknown `model_type` values (e.g. `AwsIamUser` errors). Run a default `Inventory` lookup first and read the asset's real `type` field rather than guessing; MCP-reported names can differ slightly from internal model names (e.g. `AwsRole` vs `AwsIamRole`).

> **Never trust the query's "inactive" wording, re-check the field.** A natural-language `discovery_search` for "inactive X" is unreliable both ways: it returns empty for some providers even when inactive identities exist, and it can include *active* identities in the results. Query broadly (by identity type) and decide inactivity yourself from each asset's `IsIdentityActive` / `LastActiveTime`, never from the fact that an item came back.

> **Working with `discovery_search` results in practice** (both are common): (1) **Results routinely exceed the tool's token limit and get dumped to a file.** When that happens, don't try to read the whole file, grep/`jq` it for just the fields you need: `Name`, `IsIdentityActive`, `LastActiveTime`, `RiskLevel`, `Type` (and `total_items` for the count). This file-mining is the biggest source of wasted calls if you read blobs whole. (2) **Phrasing changes results.** For Azure, "users in **tenant** X" returns data where "users in **account** X" comes back empty; if a scoped query is unexpectedly empty, retry with tenant/provider phrasing before concluding there's nothing there.

### Step 3: Decide what is actually inactive

Primary signal, identical for **all six providers**: `IsIdentityActive: false` (default 90d window) or `LastActiveTime` older than the chosen cutoff (custom windows).

Corroboration on top, where available:

| Provider | Extra inactivity evidence |
|----------|---------------------------|
| AWS | `AccessKey1LastUsedDate` / `AccessKey2LastUsedDate` old or never, `PermissionUsage` near zero; `get_cdr_events_grouped_by_event_name` (actor = identity ARN) shows zero events |
| Azure | `Recommendation` / `RecommendationType: "Inactive"` on the identity's role assignments; CDR events |
| GCP | `Recommendation` (with `total_actions: 0` inside its `additional_data`), `LastUsageTime` on binding recommendations; unused service-account keys; CDR events |
| Alibaba / OCI / Tencent | Asset timestamps only; no recommendation layer. Say so in the output and lean fully on `LastActiveTime` |
| Groups (all providers) | Inactive when **empty** (no members) or when **every member is itself inactive**. A group with even one active member is never a cleanup candidate. Fetch members via `get_linked_entities_mapping` (the members relation, commonly `Users`); a group with zero member links is empty |

> **Window cap:** this MCP caps CDR lookback at **30 days** (`last_30_days`). Never call an identity "inactive" from CDR alone; true staleness is anchored on the asset's `LastActiveTime` / `IsIdentityActive`, and the output must say which signal decided.

Exclusions applied automatically:
- **Root / tenant-owner accounts:** never disable/delete candidates, in any cloud. AWS `<root_account>` regularly tops the inactive list with a high risk score; surface it separately with its own fixes (remove root access keys, enforce MFA, stop using root day-to-day) and keep it out of every bulk action.
- **Provider-managed / service / built-in identities:** these show up "inactive" constantly but are owned or auto-created by the cloud (or a first-party vendor). Never disable/delete candidates, removing them breaks services, org management, or SSO. Detect per provider, preferring the boolean over name-matching where one exists:

  | Provider | Exclude when | Notes |
  |----------|--------------|-------|
  | AWS | `IsAwsManagedRole == true` | one boolean covers `/aws-service-role/` (`AWSServiceRoleFor*`), `/aws-reserved/` (`AWSReservedSSO_*` Identity Center), `OrganizationAccountAccessRole`, and Control Tower / StackSets / QuickSetup roles. Route SSO cleanup to Identity Center |
  | Azure | SP `ServicePrincipalType == "ManagedIdentity"`, OR `AppOwnerOrganizationId == f8cdef31-a31e-4b4a-93e4-5f571e91255a` (Microsoft first-party); role definition `IsBuiltInRole == true` | managed identities are workload-bound; first-party Microsoft apps must not be touched |
  | GCP | service account `IsUserManaged == false` (Google service agents, e.g. `service-*@gcp-sa-*`, `@cloudservices`) | also treat provider defaults (`IsUserManaged == true` AND `IsUserCreated == false`: `@appspot`, `*-compute@developer`) as load-bearing, caution, not quick-win |
  | AliCloud | name prefix `AliyunServiceRoleFor` / `AliyunReservedSSO-` / `AliyunCS*` | **no model boolean exists**, name-match only, lower confidence |
  | Tencent | `RoleType == "system"` plus service-role name match | raw uninterpreted field, **low confidence**, verify against the asset before acting |
  | OCI | **no reliable signal** | Oracle-managed identities can't be distinguished in the data; don't auto-propose OCI roles/dynamic groups for delete, route to "review with owner" |

  Where no boolean exists (AliCloud, Tencent, OCI), say so in the output: the exclusion is name/heuristic-based and lower-confidence, so lean on "review with owner" rather than auto-proposing destructive actions.
- **Too new to judge:** identities created inside the chosen window are skipped (a two-week-old identity with no activity is new, not dead).
- **Possibly human, unclear:** listed under "review" with disable-only options, never proposed for delete.
- **Break-glass / DR identities:** dormant by design; flagged but exempt from delete. Recommend converting them to just-in-time (time-bound, on-request) access instead, so the capability stays available without the standing risk.
- **No activity fields:** absence of `IsIdentityActive` / `LastActiveTime` is never evidence of inactivity, and several types this skill enumerates carry no activity signal at all, so they can't be judged by any window and must be marked "no inactivity signal available" (never auto-proposed):
  - **AWS SSO identities** (`AwsSsoUser`, `AwsSsoGroup`, `AwsSsoPermissionSet`) have no activity fields, handle via Identity Center, don't infer inactivity here.
  - **Tencent CAM roles** (`TencentCloudCamRole`) and **OCI dynamic groups** (`OciIamDynamicGroup`) have none.
  - **AliCloud RAM roles** carry no activity signal (`IsIdentityActive: null`, no `LastActiveTime`).
  - **GCP** users only carry activity data when the Google Workspace integration is on; **OCI IdP-federated users** may lack the fields entirely; GCP service-account *keys* have `LastActiveTime` but no `IsIdentityActive`.
  - **Inventory-only types** (Linode, Anthropic, Vercel users) never have them.

  For roles/NHIs with no signal, lean on the alert-anchored path, but note Alibaba/OCI have inactive-*user* rules and no inactive-*role* rules, so a role with neither an activity field nor an alert simply can't be swept, say so rather than guessing.

  **Sample before concluding, per type and tenant.** Beyond the fixed list above, an entire tenant's telemetry integration can be off (e.g. Azure sign-in logs not configured), so a normally-populated type comes back with no activity field for *every* identity. Don't confirm this one identity at a time (it burns calls); check **3-5 identities of a type**, and if none carry the field, mark the whole type-for-that-tenant "no inactivity signal available" and stop sampling.

### Step 4: Rank by identity risk score

Per acceptance: **highest risk first**. Rank on the **inline** `RiskLevel` / `OrcaScore` that `discovery_search` returns with each result, so ranking the retrieved slice costs zero extra calls. **Never loop `get_asset_by_id` over the candidate set** (a prod account can hold ~10k inactive roles, that would be ~10k calls); reserve per-asset lookups for the **top-N you actually display** (default 25). On large accounts you rank the highest-risk slice you retrieved (see Step 2's note), not a global sort of every identity.
- Primary sort key: the inline **Orca risk score / `RiskLevel`** from the sweep payload. This is a composite Orca already computes from privilege, crown-jewel status, and alert pressure, so a dormant admin surfaces near the top on its base score alone. Rely on it as the ranking input, don't assume the bumps below are what lifts high-risk identities into view.
- **Bumps (refinements/annotations on the displayed top-N):** confirm and label privileged/admin-while-dormant, exposed credentials (`get_other_secret_occurrences`), crown-jewel reach (`get_asset_crown_jewel_info`), open alert pressure (`get_asset_alerts_count_grouped_by_risk_level`). If a bump reveals an identity the base score under-ranked, pull it up and say why. To guard the tail on large accounts, prefer querying the highest-risk / privileged inactive identities in Step 2 rather than trusting one unfiltered slice.

### Step 4b: Estimate alerts that will close (mandatory, scale-safe)

Every run must report how many open alerts the plan would close, derived cheaply enough to survive a 10k-identity account, so **never sum per-asset alert counts across the full set**:
- **Baseline (scales to any size, a handful of calls total):** each inactive identity carries at least its own inactive-identity alert, plus any unused-credential alerts. Take the **aggregate `total_items`** for the relevant inactive-identity / unused-credential alert types scoped to the account (the alert types in Step 2's table, or the discovery result counts), intersected with the candidate scope. That sum is the floor and the headline number: "~N alerts will close".
- **Precise add-on (top-N only):** for the identities you display you already pulled `get_asset_alerts_count_grouped_by_risk_level` in Step 4, so you can give an exact figure for the shown set and estimate the tail.
- **Always label it an estimate**, e.g. "~N alerts expected to close after the next scan (exact for the 25 shown, the rest estimated from alert-type totals)". Never present it as precise when it isn't, and never derive it by looping per-asset over thousands of identities.

### Step 5: Propose the action plan

Default recommendation is **disable first, delete after a grace period** (suggest 30 days disabled with no complaints, then delete). **Already-disabled identities** are detectable on the asset (Azure user `AccountEnabled: false` / service principal `IsEnabled: false`, AWS all keys inactive and no login profile, GCP service account `IsDisabled: true`): skip the disable proposal for them and propose delete-after-grace directly, noting how long they've been disabled. Present the ranked list with a proposed action per identity; the user can accept, override per identity, or act in bulk ("disable all", "delete 2, 5, 7"). If `--action` was given, pre-fill that action for every eligible identity instead of the per-identity default; `--action delete` still passes the confirmation gate in Step 6, and excluded buckets (break-glass, possibly human, too new) stay disable-only regardless.

| Provider | Identity type | Disable (non-destructive, reversible) | Delete (destructive, irreversible) |
|----------|---------------|----------------------------------------|-------------------------------------|
| AWS | IAM user | Deactivate access keys + delete console login profile | `delete-user` (after keys, MFA devices, policies, group memberships are removed) |
| AWS | IAM role | Restrict the trust policy so nothing can assume it | `delete-role` (after detaching policies and instance profiles) |
| AWS | IAM group | Remove members (group shell stays) | `delete-group` (after members and policies are removed) |
| AWS | SSO user / group / permission set (`AwsSsoUser`, `AwsSsoGroup`, `AwsSsoPermissionSet`) | Manage in IAM Identity Center, not IAM: remove the account assignment / permission-set assignment for this account | Delete the user/group/permission set in Identity Center (never via IAM); surface it, don't generate an IAM script |
| Azure / Entra | User | Block sign-in (`accountEnabled: false`) | Delete the user |
| Azure / Entra | Service principal / managed identity | Set `accountEnabled: false` | Delete the principal |
| Azure | Role assignment | Remove the assignment (re-creatable) | Removal is the fix; nothing further to delete |
| GCP | Service account | `gcloud iam service-accounts disable` | `gcloud iam service-accounts delete` |
| GCP | IAM binding | Remove the binding (re-creatable) | Removal is the fix |
| Alibaba Cloud | RAM user / role / group | Deactivate access keys + console logon profile; for roles, empty the trust policy | Delete via RAM after detaching policies and memberships |
| OCI | User / group / dynamic group | Strip capabilities (console password, API keys) via user capabilities | Delete via IAM after removing group memberships and policies |
| Tencent Cloud | CAM user / role / group | Disable console login + deactivate keys | Delete via CAM after detaching policies and memberships |

For AWS, Azure, and GCP generate exact CLI/Terraform artifacts; for Alibaba, OCI, and Tencent generate the CLI steps at mechanism level and mark them for review before running (less battle-tested surface).

Root accounts and provider-managed identities (per the Step 3 table) never enter this table; they were already excluded. **Vendor and platform roles** (third-party integration roles like security scanners or cost tools, and cross-account access roles) may pass the inactivity test yet be load-bearing: used rarely but critically, or exercised from another account so their activity is invisible here. Tag them **"review with owner"** and lean on the blast-radius links before proposing anything destructive.

**Prefer an evidence signal over the name.** For AWS, read the role's trust (assume-role) policy and flag it review-with-owner when an **external account or principal** can assume it, that cross-account trust is the concrete reason its activity is invisible to this account's scan, and it's more rigorous than matching a prefix. Azure already exposes this via `AppOwnerOrganizationId` (first-party / external owner). Fall back to name patterns (e.g. `CLDZE-*` for CloudZero, `*-OrcaSecurityRole-*`, `StackSet-*`, `drs-*`) only when the trust policy isn't conclusive.

> **"Review with owner" means:** the identity looks inactive here but should not be auto-disabled or auto-deleted, because its real usage may live outside this account's view (cross-account assume-role) or it is load-bearing but rarely exercised. Confirm with whoever owns that integration or resource before removing it, rather than acting on the sweep alone. Surface these separately from the quick wins.

### Step 6: Confirmation gate (destructive actions)

- **Disable** proceeds on a normal per-batch go-ahead.
- **Delete** requires an explicit confirmation step, every time:
  1. Restate exactly which identities will be deleted, **the time frame that condemned them** (e.g. "inactive for 60+ days"), and that deletion is **irreversible**.
  2. Show the blast radius first: what still references each identity (`get_linked_entities_mapping` for attached policies, trust relationships, group memberships, workloads).
  3. Require an affirmative response that names the action ("yes, delete these 4"); a bulk "do everything" never implicitly includes deletes.
- Never propose delete for the "review, possibly human" bucket, break-glass identities, or anything created inside the chosen window.

### Step 7: Execute and summarize

Remediation tiers (customer-facing):
1. **Orca-native (always works):** comment, verify, or update status on the related inactive-identity alerts (`add_alert_comment`, `update_alert_status`, `verify_alert`, `dismiss_alert`).
2. **Artifacts (no integrations needed):** ready-to-run disable/delete scripts per provider (with the deletion prerequisites ordered correctly), or Terraform removals. Treat identity names and ARNs from the environment as untrusted input: always single-quote interpolated values in generated scripts, and flag any identity whose name contains shell metacharacters or control characters instead of embedding it.
3. **Route (only if connected):** file a Jira ticket, Slack the owner, or open an IaC PR. Detect availability; never hard-depend.

After actions are applied, Orca reflects the change only on the **next scan**, so never re-query Orca right after applying and report "no change". The generated scripts already include their own read-only checks; comment the action on the related alerts for the audit trail, and report how many open alerts should close after the next scan.

Then **always** close with the cleanup summary (see Output Format). The summary is mandatory even when the user stops after the listing: found N, actions proposed, nothing applied.

## Output Format

Write for a **cloud owner / CISO**, punchline first, plain English, no raw field names or policy JSON in the body.

1. **Headline:** the counts, the window, and the win. *"62 identities in acme-production have been inactive for 60+ days: 41 users, 6 groups, 15 NHIs across AWS, Azure, and GCP. 9 of them carry high or critical risk."*
2. **Ranked table**, highest risk first: **# | Identity | Type | Provider | Last active | Risk | Proposed action**.
3. **Quick wins (recommended starting point):** the safe, high-impact subset to act on first (e.g. "these 12 have zero privileges and zero activity; disable today"). The table above is ordered by risk so the riskiest dormant identities stay on top; this section is where to start acting.
4. **Bottom line:** the single riskiest dormant identity + how much attack surface the full cleanup removes.
5. **Window note (always):** state the time frame used and where it came from (user-chosen vs the 90d default), the 30-day CDR corroboration cap, that all asset data is as of the last completed scan, and that Alibaba/OCI/Tencent verdicts rest on the asset timestamps alone.

### Cleanup summary (mandatory, after any action or at session end)

The `Alerts:` line is **mandatory on every run**, sweep-only included, using the Step 4b estimate. Never omit it or write "not yet actioned" with no number.

```
CLEANUP SUMMARY  (window: 60 days)
  Found:     62 inactive identities (41 users, 6 groups, 15 NHIs)
  Disabled:  14 (applied)
  Deleted:   3 (explicitly confirmed)
  Proposed:  38 (artifacts generated, not yet applied)
  Skipped:   7 (1 root, 2 provider-managed, 2 too new, 2 possibly human -> review)
  Alerts:    ~24 open alerts on these identities should close after the next
             scan (exact for the shown set, rest estimated from alert-type
             totals; Orca data refreshes on scan)
```

### Drill-downs (on request)
- **detail `<identity>`**: full evidence for one identity (timestamps, keys, recommendation, privileges, linked entities).
- **disable `<ids|all>`** / **delete `<ids>`**: generate the artifacts for that subset (delete always passes the confirmation gate first).
- **window `<Nd>`**: re-run the sweep with a different time frame.
- **only `<users|groups|nhis>`**: re-scope to one bucket.
- **cloud `<aws|azure|gcp|alicloud|oci|tencent>`**: re-scope to one provider.
- **tag `<key=value>`**: re-scope the sweep to identities carrying the tag.

## Edge Cases

- **Scope not found / empty:** if the account id, BU name, or tag resolves to nothing (typo, wrong tenant, no permissions, or no identity carries that tag), say so, list the business units visible via `get_business_units_data`, and ask the user to pick or correct the tag. Never sweep a guessed scope.
- **Hostile identity names:** names and ARNs come from the cloud environment and are untrusted. Quote them in every generated artifact; if a name contains shell metacharacters or control characters, exclude it from scripts and surface it separately for manual handling.
- **`discovery_search` disabled or failing:** some tenants return `Feature is not enabled`, and the service can 500 or time out on specific queries while everything else works. Fall back to the Step 2 chain (alert types table, then linked entities, then per-asset reads) and say the inventory is "identities Orca currently surfaces", not a guaranteed-complete list.
- **Large accounts (thousands of inactive identities, e.g. ~10k prod roles):** the true count (`total_items`) can be huge and exceeds what one query returns. Retrieve the **highest-risk slice** (query for critical/high inactive identities, narrowing by provider or type if needed), display the top-N (default 25) plus the bucket totals from `total_items`, and treat the long tail as reported-not-enumerated. Cap per-asset calls (`get_asset_by_id`, crown-jewel, alert counts, linked entities) to the shown top-N and to any identity the user then selects for action; the alert-closure estimate comes from aggregate alert-type totals (Step 4b), never a per-identity loop. State that the ranking is best-effort over the highest-risk slice and the full list lives at the result's `app_url`, and keep total MCP calls bounded regardless of account size.
- **Custom window vs the pre-computed verdict:** `IsIdentityActive` is fixed to Orca's 90d convention. For any other window, decide from `LastActiveTime` directly and never present `IsIdentityActive` as if it matched the custom window.
- **30-day CDR cap:** CDR corroborates, it never decides. Staleness is anchored on the asset's `LastActiveTime` / `IsIdentityActive`.
- **Scan staleness:** all asset fields (`LastActiveTime`, `IsIdentityActive`, risk levels, alert states) are as fresh as the last completed scan; only CDR events are near-real-time. Post-remediation proof comes from the cloud CLI checks, never from an immediate Orca lookup; alerts close after the next scan. Never re-sweep right after a cleanup expecting Orca to show the changes.
- **Missing GCP recommendations:** policy-binding recommendations are feature-flag gated in some tenants. Fall back to the identity's own timestamps and say the grant-side evidence was unavailable.
- **Google Workspace identities:** appear as GCP users/groups only when the Workspace integration is enabled; if the user expects them and they're absent, say the integration may be off.
- **Human vs NHI misclassification:** when unsure, put the identity in the "review, possibly human" bucket with disable-only options. A wrong delete on a human break-glass account is far worse than a missed cleanup.
- **Deletion prerequisites:** cloud deletes fail unless dependencies are removed first (keys, MFA devices, policies, group memberships, instance profiles, bindings). Generated scripts must order these steps correctly.
- **Federated / SSO identities:** deleting the cloud-side identity does not offboard the person or workload in the IdP (Okta, Entra ID, Google Workspace). Flag that the IdP side needs its own cleanup; AWS SSO users/groups/permission sets live in IAM Identity Center, not IAM.
- **Groups:** never delete a group with an active member; when a group is inactive because all members are inactive, clean the members first, then the group.
- **No changes without confirmation:** this skill produces the actions; the user (or a routed approval) applies them. Disable needs a go-ahead, delete needs the explicit confirmation gate. Nothing is ever auto-applied.

## MCP Tools Used

| Tool | Purpose |
|------|---------|
| `get_business_units_data` | Expand a business unit to its member accounts |
| `discovery_search` | Primary enumeration: users / groups / NHIs with `IsIdentityActive = false` across all six providers (if enabled) |
| `get_alerts_with_similar_alert_type` | Fallback enumeration via inactive-identity / unused-credential alerts |
| `get_asset_by_name` / `get_asset_by_id` | Resolve each identity; read `LastActiveTime`, `IsIdentityActive`, key last-used fields, `RiskLevel`; provider-managed flags (`IsAwsManagedRole`, GCP `IsUserManaged`/`IsUserCreated`, Azure `ServicePrincipalType`/`AppOwnerOrganizationId`/`IsBuiltInRole`); Azure role-assignment `Recommendation`; GCP `GcpIamPolicyBindingRecommendation` |
| `get_cdr_events_grouped_by_event_name` / `search_cdr_events` | Corroborate inactivity (30-day cap) |
| `get_asset_alerts_count_grouped_by_risk_level` / `get_asset_related_alerts_summary` | Per-asset open-alert counts for ranking bumps and the exact alert-closure figure, **top-N only, never looped over the full candidate set** |
| `get_other_secret_occurrences` | Bump identities whose credentials are exposed in code/images |
| `get_asset_crown_jewel_info` | Bump identities that can reach sensitive assets |
| `get_linked_entities_mapping` / `get_linked_entities_data` | Delete blast radius: what still references the identity; group membership via the `Users` relation |
| `add_alert_comment` / `update_alert_status` / `verify_alert` / `dismiss_alert` | Tier-1 Orca-native actions on the related alerts |

### Parameter notes
- `--inactive Nd` sets the time frame: default **90 days** (Orca's built-in `IsIdentityActive` convention); when the user picks another window, compare `LastActiveTime` directly. CDR corroboration is capped at 30 days by the MCP.
- `--only users|groups|nhis` re-scopes the sweep to one bucket. `--action disable|delete` pre-selects the proposed action for every eligible identity (Step 5); `--action delete` never skips the Step 6 confirmation gate.
- `--tag key=value` (repeatable) is a **scope**, an alternative to an account id or BU: sweep every identity carrying the given tag(s). It can also be added to an account/BU to narrow further. Matched via the `discovery_search` query, or by post-filtering on the identity tag fields when the query can't honor it; state in the output that results are tag-scoped and which tags.
- The `cloud <aws|azure|gcp|alicloud|oci|tencent>` drill-down narrows a completed sweep to one provider by re-running Step 2's enumeration (discovery query or alert-anchored fallback) scoped to that provider's identity models; it does not re-ask the window.
- Resolve `model_type` from a real asset lookup; don't pass guessed model names (MCP-reported types can differ from internal model names, e.g. `AwsRole` vs `AwsIamRole`).
- `get_alerts_with_similar_alert_type` takes the machine `alert_type` string plus an `alert_id` to exclude; pass a placeholder id (e.g. `orca-0`) when enumerating rather than pivoting from an existing alert.

## Implementation Notes

1. **Ask for the time frame when it's missing.** One question, sensible options (90d recommended, 30/60/180 as alternatives), then stick with the answer for the whole session. Don't silently assume, and don't re-ask.
2. **Disable-first is the spine of this skill.** Delete is offered, but the recommended flow is always disable, wait out a grace period, then delete. Make that the default proposal and let the user opt up to delete, never the reverse.
3. **Risk-first ordering is an acceptance criterion, not a nicety.** The customer promise is "highest-risk dormant identities at the top"; a dormant admin outranks fifty dormant no-privilege users.
4. **The confirmation gate is non-negotiable.** No phrasing of the request ("just delete everything unused") skips step 6; restate, show blast radius, get the explicit yes.
5. **The cleanup summary is mandatory** on every run, including read-only ones; "found and proposed, nothing applied" is a valid summary.
6. **Provider coverage is a product fact, not a guess:** AWS, Azure (incl. Entra ID), GCP (incl. Google Workspace), Alibaba Cloud, OCI, and Tencent Cloud all carry the shared 90-day activity verdict; treat a provider outside this set as unsupported and say so instead of improvising.
7. **Stay in scope, link onward:** over-privilege right-sizing and least-privilege policy work are separate flows (use `/orca-identity-review` for a single-identity permission deep dive); deep NHI hygiene (key rotation, OWASP NHI Top 10 scoring) is out of scope too. This skill sweeps breadth: find the dead weight, disable or delete it, report what changed.
