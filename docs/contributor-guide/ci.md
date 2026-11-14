# Continuous integration

This page explains what `.github/workflows/ci.yml` does, how the one long lived test org it
deploys into is configured, and how to sign off commits under the project's DCO policy. Open
work items, unmerged work and untested areas are listed at the end, under
"Handoff: open work and what still needs testing".

It used to say the workflow tests four org shapes. It does not, and has not since the org
tests moved to a single long lived org: there is no shape matrix, so exactly one shape is
exercised, whichever the test org was created from. Testing a second shape means a second
org and a second secret.

## Jobs

### `static`

Runs on every pull request and push to `main`, and on manual `workflow_dispatch`. No
Salesforce org is needed for this job. Steps:

1. `npm ci`
2. `npm run prettier:verify`
3. `npm run lint`. Besides the LWC rules, it holds the pure modules to plain JavaScript:
   each file in `PURE_MODULES` at the top of `eslint.config.js` (today `c/csvParser`,
   `c/zipReader`, `c/filesImportModel` and the import wizard's `xlsx.js`) fails
   lint if it imports `lwc`, `lightning/*` or `@salesforce/*`. A pure module is a helper inside
   a component bundle (its file name differs from the bundle's), or a shared service module,
   that works on plain values only; add each new one to the list, and the config
   refuses to load if a listed file no longer exists, so a rename cannot drop a module out
   of the rule silently. Without the rule the next edit can pull in the platform and the
   module stops being reusable outside Salesforce or testable without stubs (plan Section
   4.4, portability at near-zero cost).
   Lint also refuses `toISOString().slice(0, 10)` (and `substring`, `substr`, `split('T')`)
   anywhere in LWC code, tests included: `toISOString()` is UTC, so an evening user west of
   Greenwich gets tomorrow (QA review Q11). Use `isoDate()` from `c/barnFormat` for today or
   any local day, and `utcIsoDate()` for the UTC day of a UTC timestamp; `barnFormat.js` is the
   one file exempt.
   The next workflow step, `npm run lint:slds`, runs Salesforce's SLDS linter
   (`@salesforce-ux/slds-linter`, pinned in `package.json`) over every component's HTML and
   CSS under `packages/`, failing the build on any SLDS 2 (Cosmos theme) finding: a
   hard-coded color, spacing, font size, shadow or radius instead of a `--slds-g-*` global
   styling hook, a deprecated `--lwc-*` design token, a private or unsupported hook, an
   override of an SLDS class, a retired class name (`--` modifiers instead of `_`), or the
   modal close button issue. The CLI exits 0 when it finds warnings only, and most SLDS 2
   findings are warnings, so the script passes only when the linter prints "No SLDS
   Violations found". `npx slds-linter lint packages --fix` applies the safe fixes; review
   each one.
4. `npm run test:unit:coverage`. `jest.config.js` sets a `coverageThreshold` (statements 89,
   branches 79, functions 89, lines 89: about two points under the 2026-11-12 totals), so the
   step fails when coverage drops below it. Raise the floor as coverage rises; never lower it
   to land a change. Each component test also calls `expectAccessible(element)` from
   `barn/a11y` (`packages/core/test/jest-helpers/a11y.js`): it fails on a lightning form
   control with no label, a button icon or button menu with no alternative text, a button or
   link with no text, an image with no `alt`, or a positive `tabindex`, and it also runs
   `@sa11y/jest` (axe-core with Salesforce's rules) whenever that package is installed (it is
   not a devDependency yet). `scripts/ci/check-jest-a11y.py` fails the build if a component
   with a template has no test making that call and is not in
   `scripts/ci/jest-a11y-baseline.txt`, or if a baseline entry now makes it; the baseline only
   shrinks (QA review Q5).
5. `scripts/ci/check-namespace.sh`, failing the build if a hard-coded namespace prefix
   appears in source.
6. `scripts/ci/check-standard-objects.sh`, failing the build if a standard Salesforce
   object is referenced outside `packages/mirror` and `packages/mirrorgiving` (Mirror for
   Giving, split from Mirror by ADR-NEXT mirror independence, under the same rule), and separately if any Apex or metadata
   file names a Nonprofit Cloud object. The second half covers the fundraising objects, the
   objects a household is actually built out of there (`PartyRelationshipGroup`, whose Type
   of Household is what makes an Account a native household, and `AccountContactRelation`,
   which carries membership), and the contact point objects. It is checked in Apex and
   metadata only, because a component's JavaScript cannot reference an SObject and several of
   our own component names are the same words. This half was added after an audit found the
   gate matched `GiftTransaction` alone, so Core could have named the two objects Nonprofit
   Cloud households are made of and the build would have passed.
   It also checks Mirror's and Mirror for Giving's object and field declarations (everything
   under `packages/mirror/**/objects/` and `packages/mirrorgiving/**/objects/`): their Apex may name Campaign or Opportunity as strings,
   but a lookup, formula or field declared on one of those objects is resolved at deploy time
   and refuses the install where the object is absent. A folder named after a denied object
   fails, and so does a denied name in the file outside its prose (label, description, help
   text, values).
   The next workflow step, `scripts/ci/check-person-account-fields.py`, closes the gap both
   gates leave: a static reference to a Person Account field (`IsPersonAccount`,
   `PersonEmail`, `PersonMailingPostalCode`, any `__pc` or `__pr` field) anywhere under
   `packages/`. Apex comments and string literals are ignored,
   because holding the name as text and resolving it through describe is the allowed seam
   (`dynamic-apex.md`); a token such as `Account.PersonEmail`, a static SOQL query naming one,
   an `@salesforce/schema` import, a `field-name` attribute, or a metadata reference such as a
   permission set field grant fails. Custom metadata records are data and are skipped. There
   is no exemption marker.
   The step after it, `scripts/ci/check-field-references.py`, fails the build when Apex, a
   component or metadata names one of BarnCRM's own custom fields or objects that no
   package defines any more. **The dev gate orgs (oi-test, barn-sales) keep every field ever
   deployed to them, so a reference to a removed field still compiles there and the org
   gates pass. Only this check or a clean org (barn-npc) catches it.** That is how
   `Integration_App__mdt.Install_Url__c`, removed in #666, came back in a SOQL SELECT in
   #681 and failed the check-only deploy to barn-npc.
   - The index is every `objects/<Object>/` folder and `fields/<Field>.field-meta.xml`
     under `packages/`, plus sharing reasons, report types (`Gifts__c`) and child
     relationship names (`Gift_Allocations__r`).
   - A custom name is `Name__c`, `Name__mdt`, `Name__e` or `Name__r`. A namespaced name
     (`npsp__Name__c`) belongs to another package and is skipped.
   - `Object.Field__c` on an object the repo defines (a standard object counts when the
     repo adds a field to it) must name a field of that object. A static SOQL query on a
     repo object must name only that object's fields; a subquery is checked against its
     own FROM. Any other unnamespaced custom name must exist somewhere in the repo.
   - Fields on an object the repo does not define (`GiftTransaction.X__c`, a query FROM an
     NPC object) are skipped. So are Apex comments and string literals (dynamic SOQL and
     `record.get('X__c')` are the describe seam), Jest tests, metadata prose (label,
     description, help text, values) and XML comments. In JavaScript only
     `@salesforce/schema` imports and strings that are exactly `Object.Field__c` count; in
     HTML, `field-name` and `object-api-name` values.
   - Custom metadata records are checked too: each `<field>` must be a field of the
     record's type.
   - A justified exception goes in `scripts/ci/field-references-allowlist.txt` as
     `path token  # reason`, with the token as the check prints it. It has no entries today.
   - Its tests are in `scripts/ci/tests/test_check_field_references.py`.
7. `scripts/ci/check-object-allowlist.py`, failing the build if Apex or an `objects/`
   folder anywhere under `packages/` names a standard object that is not on the allowlist
   in that script. This is the other half of check 6 and the stronger shape: check 6 is a
   denylist, so it can only fail on a name somebody thought to write down, and the failure
   that matters is the object nobody thought of. A static Apex reference to an object a
   subscriber org does not have is a compile error, and one compile error in one class
   refuses the whole package, so the promise that Core installs on a Platform-only org
   (ADR-0009, ADR-0013) needs a gate where everything is forbidden unless it is listed.
   Each allowed name carries its reason on its own line in the script. Names are read only from positions where a bare identifier can be an
   SObject (`new X(`, `List<X>`, `X.SObjectType`, `FROM X`); the docstring says why that is
   narrower than every possible reference, and an unrecognized name always fails, so
   widening the patterns is safe.
   A line carrying the `// detection-only:` marker is skipped, the same marker check 6
   honours and for the same reason: a name held as a String constant, or inside the text
   of a query only run after a describe says the object is there, is not a compile-time
   reference and cannot refuse a deployment. That is the pattern ADR-0009 requires for an
   object a subscriber org may not have, so the gate permits the one shape the
   architecture insists on.
8. `scripts/ci/check-custom-metadata.py`, failing the build if a shipped custom metadata
   record names a field its type does not define. Such a record refuses the whole
   deployment, and nothing else in the suite sees it: the offline Apex compiler does not
   read custom metadata records. It also fails a record that uses the `xsd:` prefix
   without declaring `xmlns:xsd`, a label over 40 characters, and a missing label (see
   "Resolved 2026-09-22" below). And it compares each migration import template (key
   `npc_` or `npsp_`) with its sample export in `docs/admin-guide/samples/`: the Apex tests
   build rows from the template's own headings, so only this sees a misspelt heading.
   `scripts/ci/check-labels.py` does the same for custom labels: a name or short
   description over 80 characters, a value over 1000, or any of them missing, each of
   which only an org would otherwise report.
   `scripts/ci/check-label-budget.py` fails when the label total across all packages
   passes its budget (3,215; target 3,000), when a label is referenced nowhere in
   `packages/`, or when a label reads as help prose (a sentence whose name ends in a help
   word such as `Intro`, `Help`, `Description`, `Note` or `Empty`; see the script's docstring). An org allows 5,000 custom labels; installed managed package labels do not
   count, but every source deploy does, beside the org's own labels, and a source deploy
   never deletes a label. Reuse an existing label of the same text and meaning (Core's
   `Core_Kit_Save`, `Core_CmdtManager_CancelButton`, `Core_OrgOptimizer_Refresh`, the
   `Core_Shared_*` words and the `Core_Format_*` patterns such as `{0} ({1})`; modules may
   use a Core label once it is unprotected) before adding one. Help and guidance prose
   is never a label: it goes in the package's help catalog (`docs/contributor-guide/ux-kit.md`,
   Help Text; ADR-0164 `0164-help-text-json.md`).
   `scripts/ci/check-apex-budget.py` fails when a package's non-test Apex, measured as the
   org measures it (every character but comments; `@IsTest` classes excluded), passes its cap
   (`CAPS` in the script, about 2 percent above each package's size on 2026-11-05), or when a
   package has no cap. An org allows 6,000,000 characters for its own code and every unmanaged
   BarnCRM package together, and scratch orgs allow 10,000,000, so only this sees growth.
   Raise a cap only in the pull request that needs it, and say why. The trim pass targets
   3,600,000 for the full suite and 2,000,000 for Core (the check reports the gap);
   `--report` prints each package's size and the largest classes.
   **Apex is indented with tabs** (`"useTabs": true` in the `*.{cls,trigger}` override of
   `.prettierrc`, with `tabWidth` still 4 so lines wrap where they did). The org counts every
   character but comments, leading whitespace included (about a quarter of the source was
   indentation), and a tab is one character where four spaces are four: on `oi-test`, BarnHelp's
   `ApexClass.LengthWithoutComments` fell from 4,380 to 3,672 (16 percent), and the whole suite
   from 4,394,706 to 3,523,686 characters (Core from 2,421,585 to 1,942,950). Format with
   Prettier and the repository's configuration, so a hand-indented file does not creep the
   count back up.
   `scripts/ci/check-help-text.py` checks those catalogs (`BarnHelp_<Package>.json`): every
   key a `helpText`, `BarnHelp.text` or `help-key` names is in its package's catalog and
   written as a literal, every catalog key is used and is not also a label, translations are
   listed and hold only English keys, no text holds an em or en dash, and code reads only its
   own package's and Core's help.
   `scripts/ci/check-metadata-lengths.py` (`npm run check:metadata-lengths`) covers the
   other limits only an org reports: a description over 255 characters on a custom
   permission, permission set, permission set group, FlexiPage, Lightning web component
   bundle, tab or app; a field label over 40, inline help over 510, a field or object
   description over 1000, a custom label value over 1000; two layout actions with the same
   sort order or name; a record page visibility rule that tests a lookup field itself (the
   platform refuses EQUAL and NE there, so test a field across it, such as
   `{!Record.Donor_Account__r.Name}`); a dynamic related list column value that names
   several fields instead of one per `valueListItems`; and an Apex class, interface or enum named after a reserved Apex type
   (Page, Package, Type, Object, Limit, Group, Case, Sort, Select, Trigger, System, Schema,
   Database). Lengths are counted with leading and trailing whitespace trimmed but the line
   breaks and indentation inside counted, as the platform does, so a description that
   Prettier wraps across lines needs a few characters of room.
9. `scripts/ci/check-symlinks.sh`, failing the build if a tracked file is a symlink
   pointing outside the repository or at an absolute path. Such a link resolves on the
   machine that committed it and dangles everywhere else, so every local check passes and
   CI fails. This ran because a stray `.tools` symlink, left in an agent worktree and swept
   in by `git add -A`, broke the offline Apex compile check on `main`.
10. `scripts/ci/check-permission-sets.py`, failing the build if a packaged permission set
   grants access to a class, tab, app, custom permission, object, record type or field that
   the repository does not ship, or a permission set group contains a set that is not there. A dangling grant refuses the whole deployment, and the
   permission sets are assembled by hand at every merge from each branch's integration
   file, so the reference and the metadata can drift apart silently. This ran because
   `BarnCRM_Admin` granted a `Household_Member__c` tab that was never created.
   Alongside it, `scripts/ci/check-generated-permission-sets.py` (D-200 S9a) fails the build
   when a role trio's Admin or Read Only set differs from its Staff set plus its delta in
   `scripts/permission-sets/deltas/<Prefix>.json`. Those two sets are generated: change the
   Staff set or the delta, then run `python3 scripts/permission-sets/generate.py`. The
   committed XML stays the deployed source, and ADR-0194's permission model is unchanged.
   `--bootstrap <Prefix>` writes the delta that reproduces a trio's current sets.
11. `scripts/ci/check-help-links.py`, failing the build if a Setting Definition's Learn
   more link points at a page that does not exist. `SettingsController` appends
   `Help_Path__c` to a base already ending in `docs/admin-guide/`, so a row storing
   `admin-guide/access.md` produces a 404 that nothing else notices: the value is a string,
   so it deploys, and it is only wrong once an administrator clicks it in an org looking for
   help. This ran because twelve of the thirty four shipped rows did exactly that.
12. `scripts/ci/check-adrs.py`, failing the build if a decision record's number disagrees
   with its own heading, if two records share a number, if a record is missing from the
   index, or if an `ADR-NEXT` placeholder survives to `main` (that placeholder is how a
   parallel branch avoids guessing a number, and the integrator assigns the real one at
   merge). Parallel branches pick the next free number at the same time and collide, so
   renumbering at merge is routine, and a renumber that renames the file but not the heading
   leaves a document that argues with itself. This ran because two branches both claimed
   0025 in one afternoon, and because ADR-0024 was written and never indexed, which is how
   the next author picks a number that is already taken.
13. `scripts/ci/check-visual-standard.py`, failing the build if a Lightning web component
   adds a look the suite visual standard replaced: `slds-text-title_caps`, a solid
   `slds-box slds-theme_*` message, a `slds-table` that does not stack on a phone (unless it
   carries `data-wide-table`), or an inverse badge. Screens
   built earlier are counted in `scripts/ci/visual-standard-baseline.txt`; a count may only go
   down. See [UX kit](ux-kit.md#visual-standard).
   `scripts/ci/check-components-reachable.py`, failing the build if a Lightning web
   component marked `isExposed` is on no flexipage, in no quick action, nested in no other
   component, and not named in the settings console import switch. Exposed means an
   administrator *could* place it, never that the package ships anywhere that does, and an
   unreachable component is a feature that does not exist however green its tests are. This
   ran because it has happened four times: the three C-15 to C-17 panels while their guides
   said "scroll to the card", `receiptSettings` named across a package boundary the console
   cannot cross, `receiptActions` while the receipts walkthrough said "click Issue receipt",
   and `commitmentSchedulePreview`, which no guide ever mentioned at all.
14. `scripts/ci/check-record-pages-assigned.py`, failing the build if a packaged record page
   flexipage is named by no `actionOverrides` assignment, or if an app assigns one for some
   of the form factors it declares and not the others. Item 12 proves a component is on a
   page and says so in its own header that it proves nothing about the page: a FlexiPage
   cannot name the record type it serves, that assignment lives in the Lightning app, and a
   page nothing assigns is never shown, so the component sits on a page nobody opens. Same
   defect class one level up, and the same symptom: it deploys, every test passes, and the
   administrator sees none of it until they wire it up by hand in the Lightning App Builder.
   This ran because `BarnCRM.app-meta.xml` carried no `actionOverrides` at all, so the
   household walkthrough failed at step 4 on every fresh install, and because
   `Gift_Record_Page` and `Commitment_Record_Page` were stranded the same way in Fundraising.
   Beside it, `scripts/ci/check-record-page-copies.py` fails the build if a module copy of
   Core's `Contact_Record_Page` or `Account_Record_Page` (`<Prefix>_Contact_Record_Page`,
   ADR-0064) lacks any component Core's page has. A copy may add panels, never drop one; the
   Programs and Volunteers copies had silently lost four Core components (D-200 R2).
15. `scripts/ci/check-canonical-model.py`, failing the build if a shipped object or field
   is missing from `docs/architecture/canonical-model.md`. The canonical model is updated
   before an object or a field is added, so this is the gate that keeps it true. It checks
   both directions. Inside the model: no API name declared twice for one object, and no
   name used in prose that no table declares. Against the metadata: every folder under
   `packages/*/main/default/objects/` is named in the model, and every custom field shipped
   in it is named in backticks in a top-level section that also names that object. Until
   2026-10 only the first direction ran, so this line claimed more than the script did, and
   four custom metadata fields had shipped with no API name in the model.
   `scripts/ci/check-openapi.js` (`npm run check:openapi`) fails the build if
   `docs/architecture/reference/inbound-gift-api.openapi.yaml` does not parse as YAML, is
   not OpenAPI 3.1, has a `$ref` that resolves to nothing, an operation without a unique
   `operationId` or a response without a description, or has drifted from the Apex: its
   request properties and required list against `InboundGift`, its result properties
   against `InboundGiftResult`, its `outcome` and `errorCode` values against that class's
   constants, and its two length limits against `InboundGiftRequest`. The document is only
   read by integrators' tools, never by the build, so without this a broken file or a new
   field missing from it would ship and be found by a partner. It is not a full OpenAPI
   validator, which would need a network install; it reads the file with the `yaml`
   package already in `devDependencies`.
16. `scripts/ci/check-setting-defaults.py`, failing the build if a checkbox setting that
   ships switched on is not declared in `SettingsService.SHIPPED_DEFAULTS`, or is declared
   there with a value the field metadata disagrees with. A field's own `defaultValue` is
   applied by the platform when a record is created through the user interface, and never
   by `getOrgDefaults()`, which hands Apex a materialized record with every checkbox false.
   So a feature that ships on reads as switched off on every fresh install and does nothing,
   silently, which is a defect only an org run finds (ADR-0035). This ran because C-15 had
   been writing one side of every relationship since it merged: the reciprocal upkeep read
   its own shipped default as false. The same script also fails the build if a checkbox that
   ships switched on is neither in its package's `SHIPPED_ON_ADDED_IN_UPGRADES` list (read by
   `ShippedDefaultUpgrades.apply` from the package's post-install class) nor in the closed
   `SHIPPED_BEFORE_UPGRADE_STEP` list of settings that shipped before that step existed, or if
   a listed field no longer ships on (QA-F2). A setting added in an upgrade is otherwise off in
   every org that saved settings before it, because the stored record already has the column
   as false. The step turns each listed field on once per org, tracked by a count in
   `Shipped_Defaults_Applied__c`, so an admin's later choice is never overridden. Append new
   fields to the end of the list; never reorder or remove one.
   `scripts/ci/check-setting-object-explicit.py` fails the build if a Setting Definition
   record omits `Settings_Object__c`. A custom metadata default is applied only when a record
   is created, never when a record that omits the field is redeployed or upgraded, so an org
   keeps the value it first stored. The rename of the default to `BarnCRM_Settings__c` left
   such orgs pointed at the old object and every save refused with "That setting does not
   exist in this org".
   `scripts/ci/check-apex-access-modes.py` fails the build if packaged Apex (tests
   excepted) leaves its sharing or access mode to the platform default: a class
   with no `with`, `without` or `inherited sharing` keyword (an inner class only when it
   touches the database), an inline query with no `WITH USER_MODE` or `WITH SYSTEM_MODE`, a
   DML statement with no `as user` or `as system`, or a `Database` or `Search` method with no
   `AccessLevel`. A query string that carries its own `WITH` clause is marked with an
   `// Access mode:` comment on the call's line or the line above. From API version 67.0 a
   query or DML statement with no mode runs in user mode and a class with no keyword runs
   with sharing (Apex Developer Guide, Versioned Behavior Changes), so an elevated read that
   relied on the old system-mode default fails for a user without access, and only an org
   run as that user shows it.
   `scripts/ci/check-tests-run-as.py` fails the build if an `@IsTest` or `@TestSetup` method
   in Core, Giving, Volunteers, Programs, Logic Models, Funders or Mirror (the vendored engine excepted) never calls `System.runAs` and
   carries no `// runs-as: deploying user (reason)` comment (a `@TestSetup` that only calls
   `TestUsers` is fine), or if a `TestUsers` call made in two or more test methods of a class
   is not also made in a `@TestSetup` of that class. See "Tests run as a user they create"
   below for why.
   `scripts/ci/check-aura-non-admin-tests.py` fails the build if a class with an
   `@AuraEnabled` method has no test that calls it and builds a non-admin user
   (`TestDataFactory.createUser`, `TestUsers.standardUserWith`, `peopleReaderWith`,
   `minimumAccessUserWith`, or a user on `TestUsers.readOnlyProfileId()` and the like), unless
   `scripts/ci/aura-non-admin-allowlist.txt` lists it as `# admin only: reason` or as
   `# not yet`. `TestUsers.admin()` keeps the administrator's profile, so a test run only as an
   admin cannot see a missing field permission or class grant that breaks the page for staff
   (QA review Q1: about 5,075 admin test calls against 370 non-admin). The `not yet` entries
   only shrink: one fails once its class has such a test. Write the staff test as a Standard
   User holding the package's Staff or Read Only set (`BarnCRM_Staff`, `Giving_Staff`), with
   records the user owns where the object is private.
   `scripts/ci/check-test-relevance.py` fails the build if a test class (the vendored engine
   excepted) has neither `@IsTest(testFor='...')` nor `@IsTest(critical=true)` and is not in
   `scripts/ci/test-relevance-cross-cutting.txt`, or if a `testFor` names a class or trigger
   that is not in `packages/`. See "Relevant tests" below.
   `scripts/ci/check-lwc-apex-params.py` fails the build if a component calls an Apex method
   with an object literal whose keys are not that method's parameter names. The platform
   drops an unknown key without an error and the parameter arrives as null, and a Jest mock
   accepts any shape, so nothing else sees it (ADMIN-1, ADMIN-13).
   `scripts/ci/check-aura-class-access.py` fails the build if an Apex class with an
   `@AuraEnabled` method that a component imports is granted (`classAccesses`) in no permission
   set of the package that holds the class or the component. The platform refuses the call for
   a user without that grant, and a Jest mock cannot see it (the Volunteers readiness card
   shipped broken this way). A deliberate exception goes in
   `scripts/ci/aura-class-access-allowlist.txt` as `Class  reason`.
   `scripts/ci/check-trigger-handler-records.py` fails the build if a class that extends
   `TriggerHandler` (directly or through another handler) reads `Trigger.new`, `Trigger.old`,
   `Trigger.newMap` or `Trigger.oldMap`. A handler reads its records through `newRecords()`,
   `oldRecords()`, `newRecordsById()` and `oldRecordsById()`, because the dispatcher narrows
   them and reruns a handler on the rest after a failure (ADR-0165 rule 3); only
   `TriggerHandler` reads the platform's own.
   `scripts/ci/check-trigger-static-state.py` fails the build if a trigger handler's `before`
   method assigns a new collection to, or clears, one of the handler's static `Map`, `Set` or
   `List` fields. Such a field carries what the before event noted to the after event, and a
   save of more than 200 rows (two chunks) or a dispatcher retry runs the before again, so a
   reset drops the first chunk's state (defect D1, QA review Q4). Add to it keyed by record
   Id and remove what the after event used; a deliberate reset is listed in
   `scripts/ci/trigger-static-state-allowlist.txt` with its reason. Each handler holding such
   state has a test that saves or deletes more than 200 rows at once.
   `scripts/ci/check-global-describe.py` fails the build if packaged Apex other than
   `NamespaceUtil` calls `Schema.getGlobalDescribe()`. The describe costs about 12 ms of CPU in
   a large org and cannot change within a transaction, so every class reads the one copy
   `NamespaceUtil.globalDescribe()` keeps per transaction and running user (D-143). Test
   classes are exempt.
   `scripts/ci/check-async-starter.py` fails the build if packaged Apex calls
   `Database.executeBatch` or `System.enqueueJob` directly, outside `AsyncStarter` and the
   allowance `scripts/ci/async-starter-allowlist.txt` gives each file (D-200 P9). A button or
   nightly step starts its work with `AsyncStarter.batch(work, scope, context)` or
   `AsyncStarter.queue(work, context)`: it refuses when 95 batch jobs are already waiting or
   this request may queue no more, logs the refusal once and throws
   `AsyncStarter.BusyException`, whose message asks the person to try again in a few minutes.
   The allowlist keeps jobs that chain themselves, starts from a trigger or save, post-install
   steps and batches over values; its counts must match, so lower one as a call moves over.
17. `python3 -m unittest discover -s scripts/migration/tests`, the migration kit's unit tests
   (C-31, [Migration kit](migration-kit.md)). They need no org, and one of them builds the
   mapping from the real package source, so a new object or field that breaks it fails here.
18. `scripts/ci/check-flow-templates.py`, failing the build if a switchable Core automation
   has neither a Flow template (`Template_<registry name>`) nor a row on
   `docs/admin-guide/flow-templates.md` saying why it has none, or if a template ships active
   or not marked as a template (ADR-0040, ADR-0090).
   `scripts/ci/check-whats-new.py` warns (a build annotation, not a failure) when the newest
   version named in `docs/release-notes` has no `Release_Note` custom metadata record, so the
   What's New card would still show an older release. Run with `--release` it fails instead;
   the release checklist in `docs/release-notes/README.md` runs it that way.
   `scripts/ci/check-deploy-readiness.py` (unit tests in `scripts/ci/tests`) fails the build
   on deploy errors the org gate would otherwise only find after starting: a Core folder not
   named in `CORE_STAGED` in `scripts/org/deploy-packages.sh`, a custom object whose
   `enableSharing`, `enableBulkApi` and `enableStreamingApi` are not all equal, or a custom
   object without `nameField`, `label` or `pluralLabel`, or a permission set that grants
   Create on a platform event (`__e`) without Read. The rules are listed in its header.
19. A grep check that fails the build if any tracked file contains an em dash character.
20. Installs the Salesforce CLI and the `code-analyzer` plugin, then runs
   `sf code-analyzer run --workspace packages --rule-selector Recommended --severity-threshold 2`.
   The results are uploaded as a build artifact (`code-analyzer-results.html` and
   `code-analyzer-results.json`) even if the job fails, so anyone can download and read
   them from the workflow run page.

If `packages/` has no Apex or JavaScript yet, Code Analyzer may report nothing to scan.
That is expected in the early scaffold and is not a failure.

### One command for every offline check

`bash scripts/ci/run-offline-checks.sh` runs every check that needs no org, in CI's order:
each `scripts/ci/*.py`, each `scripts/ci/check-*.sh`, the offline Apex compile check, the
OpenAPI check, the migration kit tests, the em dash scan, `npm run lint`,
`npm run prettier:verify`, `npm run lint:slds` and `npx sfdx-lwc-jest --silent`. It prints one
`PASS` or `FAIL` line per check and, for a failure only, the last 30 lines of that check's
output. The exit status is non-zero if anything failed. If `node_modules` is missing it tells
you to run `npm ci` and stops.

- `--fast` skips Jest, the `scripts/ci/tests` suite and Code Analyzer.
- `--allow-adr-next` counts a `check-adrs.py` failure as a pass when the only problems are
  unnumbered `NEXT-*.md` decision records, so a branch with a new ADR reads clean.
- `--analyzer` also runs `sf code-analyzer run --severity-threshold 2` on the Apex and
  JavaScript files changed against `origin/main`. It is slow, so it is off by default.

### Run the same checks locally, before you push

Every gate above except the org tests runs on a laptop, and all of them are fast. For a
feature pull request these, with Jest (`test:unit`), are the whole test duty: org tests run once
per landing batch, through the gate script described under "The org test gate":

```
npm run prettier:verify
npm run lint
npm run lint:slds
npm run test:unit
npm run check:namespace
npm run check:standard-objects
npm run check:object-allowlist
npm run check:custom-metadata
npm run check:metadata-lengths
npm run check:symlinks
npm run check:permission-sets
npm run check:help-links
npm run check:adrs
npm run check:components-reachable
npm run check:record-pages-assigned
npm run check:canonical-model
npm run check:openapi
npm run check:setting-defaults
npm run check:flow-templates
npm run check:tests-run-as
npm run check:test-relevance
npm run check:apex
npm run check:analyzer
```

`check:analyzer` is the one most easily forgotten, because it is the slowest and needs the
Salesforce CLI with the `code-analyzer` plugin. It is also the one that enforces a
non-negotiable: zero high or critical findings before merge. Skipping it locally means
finding out from a red build.

## Connecting a Dev Hub

Until a Dev Hub is connected, the `org-tests` job skips every shape and no Apex test has
ever been executed. This is the setup, once, by someone with administrator access to the org
being used as the Dev Hub.

A Dev Hub is not special. Any Salesforce org can be one, including a free Developer Edition,
and its edition does not constrain the scratch orgs it creates. Use a development org, never a
production org holding real constituent data: the credential below grants full API access to
whatever org it names.

1. **Enable Dev Hub in the org.** Setup, then Quick Find, then Dev Hub, then switch Enable Dev
   Hub on. The switch cannot be turned off again, which is why this belongs in a development
   org. Nothing else on that page is needed yet: second generation packaging stays off until
   the namespace question is settled (plan Section 4.3).
2. **Install the Salesforce CLI locally**, if it is not already there: `npm install -g @salesforce/cli`, then `sf --version`.
3. **Log in to the org and mark it the default Dev Hub.** `sf org login web --alias devhub --set-default-dev-hub` opens a browser; sign in as the administrator of that org.
4. **Check it took.** `sf org list` shows `devhub` with a Dev Hub marker. `sf org display --target-org devhub` shows the username and instance you expect.
5. **Prove it can create a scratch org before involving continuous integration.** `scripts/org/create-scratch-org.sh platform-only smoke --days 1` creates the org, deploys Core and assigns the permission sets. If that fails, fix it here rather than in a build log. Delete it with `scripts/org/delete-scratch-org.sh smoke`.
6. **Read out the authentication URL.** `sf org display --target-org devhub --verbose --json` prints a `sfdxAuthUrl` field. **That string is a credential**: it carries a refresh token and anyone holding it has API access to the org. Do not paste it into a commit, an issue, or a chat window.
7. **Store it as a repository secret.** In GitHub: Settings, then Secrets and variables, then Actions, then New repository secret. Name it exactly `SF_DEVHUB_AUTH_URL` and paste the value from step 6.
8. **Create the test org and store its secret**, which is the next section. The Dev Hub alone does not run any test: it is what lets you create the org that does. Expect failures on the first run that reaches the Apex tests: several hundred have been written and none has ever executed.

To rotate or revoke, re-run steps 3 and 6 and replace the secret, or revoke the connected app
session in the org under Setup, Connected Apps OAuth Usage.

### The test org is one long lived org, not a new one per run

`org-tests` deploys into a single org named by the `SF_TEST_ORG_AUTH_URL` secret. It does not
create or delete anything. If the secret is unset the job skips with a warning and no Apex
test runs.

That is a deliberate trade, and it is worth being clear about what it costs. A fresh scratch
org per run is a clean room: what passes, passes against exactly what this repository
contains. A long lived org accumulates. Deleted metadata is not removed by a deploy, so a
class or field you deleted here still exists there; a test can pass because of something left
behind by an earlier run. When a result looks surprising, recreating the org is the first
thing to try, not the last.

Two consequences follow.

**It expires, and then every run fails at login.** The org is a scratch org, and Salesforce
caps those at 30 days. Every run prints the days remaining and warns from a week out;
`scripts/org/check-org-expiry.sh` does that and never fails a build on its own. Refreshing the
org means replacing the secret, because a new org has new credentials.

**One org means one shape.** The four shape definitions still exist and still matter, but this
job exercises whichever shape the org was created from. Use `person-accounts` unless you have
a reason not to: it is the closest an ordinary Dev Hub gets to the Agentforce Nonprofit orgs
the first customers run. Testing a second shape means a second org and a second secret.

### Creating the test org and connecting it

Do this on your own machine, after the Dev Hub steps above.

The project's test org uses the alias `oi-test`. It is the org the gate script runs against
and the org the `SF_TEST_ORG_AUTH_URL` secret names, so a manual `org-tests` run and a local
gate run test the same org and cannot disagree because of a difference between orgs.

1. **Create it**, 30 days, from the shape you want to test:
   `scripts/org/create-scratch-org.sh person-accounts oi-test --days 30 --replace`
   This deploys Core, assigns the permission sets and seeds the sample data. Note the expiry
   date it prints.
2. **Store its auth URL** as the repository secret `SF_TEST_ORG_AUTH_URL`. The auth URL is a
   credential, exactly like the Dev Hub one, so pipe it straight into the secret rather than
   displaying it:
   `sf org display --target-org oi-test --verbose --json | jq -r .result.sfdxAuthUrl | gh secret set SF_TEST_ORG_AUTH_URL --repo Nonprofit-Collaborative/BarnCRM`
3. **Run `scripts/org/run-org-tests.sh oi-test --release`** on a pushed commit (see "The org
   test gate"), or dispatch the CI workflow by hand to have `org-tests` deploy both packages into
   the org and run the Apex tests there.
4. **Check the shape it reports.** The run prints what shape the org actually is, read from
   the org itself, before it deploys anything. Confirm it says the shape you meant to create.
   Nothing else in this repository records which definition the org came from, so that line
   in the build log is the record.

Refreshing it monthly is the same two commands: re-run step 1 with `--replace`, then redo
step 2 with the new auth URL. Anything typed into the org by hand is lost at that
point, which is the discipline the package needs anyway: what matters belongs in this
repository.

### The second test org (`oi-pa`)

The maintainer approved a second scratch org on 2026-09-24, alias `oi-pa`, created from
`person-accounts.json` on the `devhub` Dev Hub. It expires 2026-10-24 and is recreated from the
same definition when it does. `oi-test` expires 2026-10-23. Neither is the Platform-only
shape: both have Person Accounts, and ADR-0013 notes that even a Platform-only scratch org
keeps the standard objects, so no org run proves Core without them. The static checks and
review do that.

`oi-pa` is not named by any secret, so the `org-tests` workflow never uses it. It exists so
local gate runs and Person Account testing can go on while `oi-test` is busy or stuck. The
gate script works against either: `scripts/org/run-org-tests.sh oi-pa` posts the same
`Org tests (local)` status. No other org is used for testing without the maintainer's
approval.

Both orgs need the System Administrator profile to hold a person account record type, or the
tests that create real person accounts fail with `PersonAccountTestShape.NO_PERSON_TYPE_FOR_USER`
(PEOPLE-29). `create-scratch-org.sh` does this for the `person-accounts` and `nonprofit-cloud`
shapes; for an org created before that, run `scripts/org/grant-person-record-type.sh <alias>`
once.

When several people or agents share these orgs, take turns: one deploy or test run per org at
a time. A deploy from one branch while another branch's tests run leaves the org holding a
mix of the two.

### The org test gate

A pull request that changes deployable source cannot merge into `main` until its Apex tests
have passed in an org on its exact head commit. The `main` ruleset requires three checks:
`Static checks`, `DCO sign-off check`, and the commit status `Org tests (local)`.

**Testing is done in batches (owner decision, 2026-10-28, plan D-141).** "I want the testing to
be done in batches and optimized to go faster wherever prudent," for everything in this project
going forward:

1. **A feature pull request gets no org gate.** It runs `Static checks` and `DCO sign-off check`
   on GitHub, and its author runs Jest and the `scripts/ci` checks locally before pushing (see
   "Run the same checks locally, before you push"). No full or light org run is done for it.
2. **The integrator builds one landing batch.** Every ready feature branch is merged into one
   `landing/batch-N` branch (the first was PR #219, "Landing batch 7"). Conflicts are resolved
   once, `docs/product-plan.md` is refreshed from BMemory once, and the root docs
   (`architecture.md`, `changelog.md`, `roadmap.md`, `memory.md`) are written there.
3. **The incremental org gate runs on the landing head**, on `barn-sales` only, from a clean
   detached worktree under that org's lock (see "The incremental gate" below).
4. **Failures are fixed on the landing branch**, and the gate reruns on the new head.
5. **The landing pull request is squash-merged only after the gate passes.** The feature pull
   requests it carried are then closed as landed.

**Increments are tested fast; each version is tested end to end (owner decision, 2026-10-28,
plan D-142, amending D-141).** "I'd mostly like these initial tests to be as fast as possible
with an end-to-end test of the entire new version once a significant new version's initial
development is done and integrated. I don't want as much testing for all the incremental
changes." So there are two gates, and both post the one status the ruleset requires, `Org tests
(local)`, from your machine, not from a GitHub runner:

| | Incremental gate | Release gate |
| --- | --- | --- |
| When | Every landing batch | Once a significant version's development is done and integrated |
| Command | `scripts/org/run-org-tests.sh barn-sales` | `scripts/org/run-org-tests.sh <alias> --release`, on `barn-sales` and `oi-test` in parallel |
| Deploy | Staged; packages unchanged since the last deploy to that org are skipped | Every package, every stage |
| Tests | The changed and affected test classes, plus the `critical=true` classes (`RunSpecifiedTests`, chosen by `select-org-tests.py`) | Every test class in the commit's source |
| Coverage floor | No | Yes |
| Status description | Starts "Incremental:" | Starts "Release:" |
| Time (estimate) | About 10 to 15 minutes for a large batch (batches 9 and 10: 273 classes, about 8 minutes of tests) | About 24 minutes (both orgs at once) |

**The incremental gate uses `barn-sales`** because it is the faster gate (about 18 minutes for a
full run against about 24 on `oi-test`), its Sales Cloud contacts shape is the one most installs
have, and it has DLRS installed for coexistence. `oi-test` (Person Accounts shape) is covered by
the release gate.

**Accepted risk of the incremental gate (D-142).** The selection follows direct mentions of a
changed class or changed metadata and the `testFor` annotations only. It can miss a test that
reaches the changed code or metadata indirectly (a flow that fires on a standard object, a
field read only through describe), and it selects nothing for a changed label, layout or help
text. The `testFor` and `critical`
annotations (see "Relevant tests" below) narrow the gap; the release gate closes it before a
version ships.

**Both gates probe the Error Log after the deploy.** `scripts/org/probe-error-log.sh` publishes one
Info entry through `ErrorLogger`, waits up to two minutes for its `Error_Log__c` row and deletes it.
No row fails the gate before any test runs: Apex tests cannot see a platform event subscription
that stopped delivering, and on 2026-10-31 a deploy left `ErrorLogEventTrigger` Running but
silent on `barn-sales` (QA v21 D4), so every entry was lost. The fix is to restart the
subscription (Setup, Platform Events, Error Log Event, Suspend then Resume, or deploy the trigger
Inactive and then Active); redeploying it unchanged, or even with a changed body, does not.

### The incremental gate

```
scripts/org/run-org-tests.sh barn-sales
```

It deploys the commit you have checked out with `scripts/org/deploy-packages.sh` (skipping the
packages that have not changed since the last deploy to that org, see "Skipping unchanged
packages" below), then runs `sf apex run test --test-level RunSpecifiedTests` over the test
classes `scripts/org/select-org-tests.py` picks for the Apex changed since the merge base with
`origin/main` (`RELEVANT_BASE` to change it; on a landing batch that is every change it
carries):

- every test class changed in that range;
- every test class whose `@IsTest(testFor=...)` names a changed class or trigger;
- every test class that mentions a changed class by name (comments ignored), which includes the
  users of a changed test utility such as `TestDataFactory`;
- every `critical=true` class, so a batch with no Apex change still runs the smoke tests;
- every test class that names changed metadata (QA review Q9): a changed custom object, or
  anything under it, by its API name (on a standard object, the changed field's API name); a
  permission set, permission set group or custom permission by its name; a flow by its name
  and the custom object it starts on; a custom metadata record by its type (`Type__mdt`) and
  record name. A test utility that names the metadata (`TestUsers` names `BarnCRM_Admin`)
  counts as changed, so a change to an admin permission set selects every test that runs as
  that admin.

The vendored rollup engine's tests are never selected. No coverage is recorded and no floor is
checked. It posts `Org tests (local)` with a description such as "Incremental on barn-sales:
2984/2984 passed in 273 classes (no coverage floor)" (the size of landing batches 9 and 10
together). Results go to `test-results/org-tests.json`,
as in the release gate, and a run that returns nothing is retried once the same way. Jest is not
part of the gate: the required `Static checks` job runs it on the same head. To see what a range
selects without an org: `python3 scripts/org/select-org-tests.py <base> [<head>]`.

**Why not `RunRelevantTests` (2026-10-28).** The gate first deployed the changed Apex again with
the deploy-only `RunRelevantTests` level (Spring '26, beta) and let Salesforce choose the tests.
On landing batches 9 and 10 that deploy carried 83 changed Apex files, about 60 of them test
classes, and ran only the 5 `critical=true` classes (153 tests): neither the test classes in the
payload nor the `testFor` annotations were honoured, and the gate passed without running the
changed tests. The choice is now made in the repository, where it can be read and tested
(`scripts/ci/tests/test_select_org_tests.py`), and the `testFor` annotations are still used.

`--full-deploy` deploys every package even when unchanged. The `--light` mode (deploy plus Jest,
no Apex test, for screen-only changes) was retired on 2026-10-28: the incremental gate does the
same job and also runs the relevant Apex tests.

### The release gate (version end to end)

When a significant version's development is done and integrated:

1. **Run the release gate on every org shape in parallel** (QA review Q2 and Q6, D-200,
   widening D-142):

   ```
   scripts/org/release-gate.sh [--multi-currency <alias>]
   ```

   It first runs Code Analyzer over every package with the AppExchange selector and the Graph
   Engine (`sfge`, needs Java 11 or later), as the security review does, and stops on any High
   or Critical finding (`--analyzer-only` runs just that). Then it runs
   `run-org-tests.sh <alias> --release` on each org in `RELEASE_ORGS` (default `barn-sales`,
   `oi-test`, `barn-platform` for Platform-only, `barn-npsp` for an NPSP-shaped org), each from
   its own detached worktree at HEAD under its own lock, with logs and results in
   `test-results/release-gate/`. `--multi-currency <alias>` adds a multi-currency org
   (`config/scratch-defs/multi-currency.json`), once per version. It never creates an org: an
   alias not authenticated on the machine stops it before any deploy, so until `barn-npsp`
   exists (it needs Brandon's approval, and `install-npsp.sh` needs verified package IDs) set
   `RELEASE_ORGS` to the orgs that do and name the missing shape in the release notes.
   Then run the OWASP ZAP baseline scan (passive only, Docker) on the test org's Site for the
   guest surfaces (Forms, Events public pages, Payments webhooks, Portal login):
   `scripts/org/zap-baseline.sh <site URL> [<form Id>] [<event Id>]`. A FAIL stops the version;
   each WARN is reviewed against the [security checklist](security-checklist.md).

2. **Re-validate and deploy to `barn-npc`** (Nonprofit Cloud trial, production edition; see the
   gotchas in the root `architecture.md`: Public visibility for custom settings and metadata,
   and a destructive pre-step for components deleted since its last deploy).
3. **Re-validate and deploy to `mwdbdevsb`** (the real-org sandbox). Check-only first, and each
   deploy there needs Brandon's approval.
4. **QA and UX testing** of the version.

`--release` is a flag on purpose, so nobody runs the long gate for an increment by accident.
Because both orgs post the same `Org tests (local)` context on the same commit, a passing run
never replaces a failure that the other org posted there: it prints "Held" and posts nothing, so
the failure stays visible until it is fixed (a new head) or that org's gate is rerun.

The release run always deploys every package (it implies `--full-deploy`), runs every
Apex test class in that commit's source (assigning no permission set to you first: see "Tests
run as a user they create" below), and
posts `Org tests (local)` on that commit: success only when every test passed and coverage is
over the floor, failure otherwise. Its description starts "Release:". It names the test classes rather than running
every test in the org, because the test org is shared: another branch's deploy can leave its
own test classes behind, and those would fail on code this commit does not contain. The
vendored rollup engine's own tests (531 methods, about 70 seconds) are left out: no BarnCRM
runtime path calls the engine, ADR-0082 deletes it in slice S9, and they test the upstream
project. Its classes are still deployed.
The results are written to `test-results/org-tests.json`, which git ignores.

**Every release run checks code coverage.** The tests are enqueued with coverage on, so the org
records it, and the run is followed by polling its `AsyncApexJob` every `TEST_POLL_SECONDS`
(15) for up to `TEST_WAIT_MINUTES` (90). The results are then fetched without coverage, and
coverage is read separately from the org's per-class totals (`ApexCodeCoverageAggregate`
through the Tooling API, a few hundred rows). Only Apex in the commit's source counts: not test
classes, not the vendored engine, not whatever another branch left in the shared org. The run
fails, with every test passed, when:

- BarnCRM's total coverage is under `COVERAGE_TOTAL_FLOOR` (75%), or
- a class is under `COVERAGE_CLASS_FLOOR` (75%), unless it is listed in
  `scripts/org/coverage-floor-exceptions.txt`, in which case it may not fall below the figure
  recorded there. That list holds the 23 classes that were under 75% when the floor came in
  (four had no coverage at all). Raise a figure when tests improve it, and remove the line
  once the class reaches 75%; the run says which ones have.

Per-class figures (covered lines, total lines, percent, floor, result) are written to
`test-results/coverage.tsv`, and the status description carries the total and the count of
classes under their floor, for example "Release: 2700/2700 passed on oi-test, coverage 90%, 0
class(es) under floor". The org-wide figure (`ApexOrgWideCoverage`) is recorded in that file
for information only: it counts the vendored engine, whose tests the gate no longer runs, and
anything other branches left in the org, so it cannot judge one commit.

Four rules make the status worth trusting:

- **It belongs to one commit.** A new push has no status, so the pull request is blocked
  again until someone reruns the script. A pass on an earlier commit never carries over.
- **It refuses a dirty working tree.** The status is posted on `HEAD`, so the code tested
  has to be the code at `HEAD`. Commit or stash first.
- **It refuses an unpushed commit**, which GitHub could not attach a status to anyway. It
  checks before deploying, so you find out in a second rather than after the run.
- **A success never hides another org's failure.** Before posting success, the script reads the
  newest `Org tests (local)` status on the commit; if it is a failure or error whose description
  names a different org, it posts nothing and prints "Held". A failure always posts.

A pull request that changes nothing under `packages/`, `scripts/org/`, `config/`, or
`sfdx-project.json` (documentation, the workflow itself, a Dependabot bump of an action) has
nothing an org run could catch. The `Org tests not needed` job posts the status for it, so it
needs no org run. A pull request from a fork gets a read-only token and cannot post it that
way, so a maintainer runs the script for it, which is the right outcome for untested code from
outside anyway.

**Test classes run in parallel**, each in a transaction that rolls back, and each as a user it
creates for itself (see "Tests run as a user they create" below), not as the user who started
the run. That also keeps classes from colliding over what the platform keeps per user, which
used to make tests fail now and then for no reason in their own code when every class ran as
the same person. Two such collisions were found: a permission set assignment to the running
user (one row per person and set, so a second insert is refused), and a saved file (it goes
into the user's private library, and a save is refused with `INVALID_CROSS_REFERENCE_KEY,
invalid cross reference id: []` while another transaction on that library rolls back). The
few tests marked `// runs-as: deploying user` still share the running user, so they must do
neither. The gate gives that user no BarnCRM permission set, so they must need none either: a
describe or field access check counts (three classes that check field access while parsing a
filter or an import row failed this way and now run as a `TestUsers` user). A test that saves
a receipt, letter or logo file runs as
`ReceiptTestDataFactory.issuer()`.

**A test run that returns no results is retried once.** When `sf apex run test` comes back
with no test results and its output names `UNKNOWN_EXCEPTION` or a platform or network error
(or is empty), the script waits `TEST_RETRY_WAIT_SECONDS` (300 by default) and runs the tests
once more. A run with any result, including real failures, is never retried. Deploy stages
that stall are resubmitted too: see "Stalled deploys" under `org-tests`.

**At about 2,200 tests the sf CLI used to run out of memory reading the results.** The Node
process aborted with `JavaScript heap out of memory` after every stage had deployed. The cause
was the per-test code coverage that `--code-coverage` pulls into the result, not the
passing-test detail: in a 2,805-test run, coverage was 102 MB of the 313 MB result against
1.1 MB for the tests themselves. Fetching the results without coverage and reading the
per-class totals separately (above) removes that payload, so the script no longer raises the
Node heap to 8 GB. If the CLI still crashes, or returns empty or unreadable output, or the run
is still going after `TEST_WAIT_MINUTES`, the script prints "sf CLI crashed, rerun", exits 3,
does not retry, and posts no status (it used to post a failure reading `0 of 0 failed`).
Rerun the gate.

**One test depends on Salesforce's own duplicate matching.**
`DuplicateServiceTest.theStandardRuleForPeopleFindsIdenticalTwinsOnce` asks the platform's
matching service about two identical contacts inserted in the same test. In a full parallel
run it has failed once with no pair found, and passed when its class was rerun alone. A
failure of that test alone, on a change that does not touch duplicates, is a reason to rerun
the gate, not to change the code.

**The org allows a fixed number of test classes per rolling 24 hours** (`DailyAsyncApexTests`
in `sf org list limits`). Several gate runs in a day can use it up, and then every run,
including the gate, fails at once with `UNKNOWN_EXCEPTION` before any test starts.
`--synchronous` runs of one class still work, one at a time for the whole org.

While you iterate, use `sf apex run test --class-names <Class> --target-org <alias>` for one
class, or the relevant-tests run above for a branch; the full run is the final run before
merge, not the inner loop.

**An org deployed by source is not an upgraded org until setup runs (QA-C-04).** A source
deploy runs no install handler, and `run-org-tests.sh` passes `SOURCE_POST_INSTALL=0` on
purpose: the Apex tests assume an org that has never saved BarnCRM Settings, and a test org
marked as a new install has every feature off. So after a release gate, and before QA or UX
testing on the same org, run Core's setup once, then each module's setup that the org has
(`deploy-packages.sh` runs the same block when it is not told otherwise):

```
echo 'CorePostInstall.runAsSourceDeploy();' | sf apex run -o <alias>
for m in Rollups Giving Volunteers Programs LogicModels Funders Mirror MirrorGiving; do
  echo "new ${m}PostInstall().runSetup(UserInfo.getUserId());" | sf apex run -o <alias>
done
```

Until then shipped import template names keep their old casing, templates added by a later
version (Relationships, Affiliations) are missing, shipped templates keep the people mode they
were created with, and `Shipped_Defaults_Applied__c` is empty, so the upgrade scripts in the
Testing Guide (T-SET-22, T-IMP-22, T-IMP-01) cannot pass. The nightly run is scheduled by setup
only on a new install, or by adopting a schedule an earlier version had; an org with neither
shows **Schedule Nightly Jobs** on the Nightly Jobs panel (T-SET-25 steps 3 and 4), so step 1
of T-SET-25 needs an org that really was upgraded. The gate script does not run setup itself:
it marks the org as set up and changes org state (it renames templates and realigns their
people mode), which the next gate run's tests must not see. It is safe to run twice. Do the same
after the `barn-npc` and `mwdbdevsb` deploys.

### Release destructive manifest

A source deploy adds and updates components but never deletes one. A class, label, field or
tab a release removes stays in every org that had it, keeps counting toward the org's Apex,
label and object limits, and can break a later compile (`barn-npc` kept 77 stale components
in October 2026). So every release to a long-lived org (`barn-npc`, `mwdbdevsb`, and every
organization's own org) carries a destructive manifest for what was removed since the version
that org has:

```
python3 scripts/org/build-destructive-manifest.py <org's version> <release> \
  --packages core,rollups --out release-<version>/destructive
```

- `<org's version>` and `<release>` are git refs (tags, branches or commits). `--packages` names
  the packages the org has. A component that moved to another package is not removed.
- Test orgs and long-lived orgs rarely sit on one version. Build the manifest from each version
  in use and keep the union of the members (a member an org never had is only a warning, which
  `--ignore-warnings` accepts). `release-0.17/destructive` is that union for releases 0.15 to
  0.17: the removals since `19463c55` (before landing batch 8) and since `main` at `c06865c6`
  (6 classes and the label and content asset removals of batch B; `Import_Row_Retention_Days`,
  `ImportRowPurgeBatch`, `ErrorLogRetention`, `NightlyJob`, `NightlyJobProvider` and
  `NamedNightlyJob` are in it).
- Before QA on an org, compare its `Setting_Definition__mdt` names with the repo's: a definition
  the repo lacks (QA-C-02: `Import_Row_Retention_Days`) shows a setting that nothing reads. The
  Settings page already leaves out a definition whose field is missing.
- It writes `package.xml` (empty) and `destructiveChangesPost.xml`, and prints the count per
  type. A removed record type is printed instead (the Metadata API cannot delete one:
  deactivate and delete it in Setup), as is any removed file whose type the script does not
  map; either makes the exit status 1.
- Deploy it with the release: add `--post-destructive-changes <dir>/destructiveChangesPost.xml
  --ignore-warnings` to the release's `sf project deploy start` (the warnings are members an
  org never had).
- Deploy it first, on its own, when removed labels must free room before the release adds
  labels (the label limit is checked before the deletions run) or when a stale component would
  fail to compile against the release: `sf project deploy start --manifest <dir>/package.xml
  --post-destructive-changes <dir>/destructiveChangesPost.xml --ignore-warnings`. A removed
  class that an old class the release changes still calls cannot go first; it stays in the
  release deploy.
- Abort BarnCRM's scheduled jobs before a manifest deletes a schedulable class, and schedule
  them again after (`deploy-packages.sh` does this for its own deploys).
- Record the member count with the release in the org's row in the root `architecture.md`.

**What a redeploy overwrites.** A source deploy replaces each shipped component whole, so an
administrator's edit to one is lost at the next release: an object's sharing setting (a change
to or from Private also starts a sharing recalculation), record pages, page layouts, list
views, permission sets and groups (record type access a set no longer names is removed),
picklist values on shipped fields, validation rules, labels, flow templates, and shipped
custom metadata records such as `Automation_Registry__mdt` and `Setting_Definition__mdt`.
Records, the settings saved in BarnCRM Settings, and components the organization made itself
are kept. The Admin Guide (Installing BarnCRM, Upgrading) tells administrators to clone a
shipped component rather than edit it.

### Package install and upgrade test

`scripts/org/package-upgrade-test.sh` installs real package versions into new scratch orgs,
one per org shape (plan Section 4.2), and upgrades them: the test the source deploys above
cannot be. It is written now and run later: package versions wait for the namespace, Dev Hub
and steward entity (D-87), and D-173 places the first run after the v1.0 test cycle and
before the first production pilot, as a sandbox-only managed beta. Until the namespace is in
`sfdx-project.json` it exits 2 unless `--plan` is given.

**What one run does.** It reads the namespace, the packages and their dependency order from
`sfdx-project.json` (nothing is hard-coded), then:

1. Builds version N-1 from `--from` and version N from `--to`, each in a temporary detached
   worktree, with `sf package version create --code-coverage --installation-key-bypass
   --wait`, in dependency order. A file of existing `04t` ids (one `<package key> <04t>` per
   line, `#` comments allowed) skips the build for that side.
2. For each shape (`--shapes platform,sales,npsp,npc`, default all four, mapped to
   `config/scratch-defs/platform-only.json`, `sales-cloud.json`, `npsp.json` and
   `nonprofit-cloud.json`): creates a scratch org with `--no-namespace` (a subscriber org),
   installs NPSP for the `npsp` shape with `scripts/org/install-npsp.sh`, and installs N-1 in
   dependency order (`sf package install --wait --publish-wait --security-type AdminsOnly
   --no-prompt`).
3. Checks N-1 as the installing admin: the installed versions (`sf package installed list`),
   Health Check with no error finding (`health-check.apex`), and no Error Log row since the org
   was created.
4. Loads the sample data (`scripts/org/seed-sample-data.sh <alias> --namespace <ns>`) and
   records the counts of the records it writes (households and contacts, members,
   relationships, affiliations, gifts, allocations, funds, volunteer hours and jobs).
5. Upgrades every package to N in dependency order and checks again: versions are N, Health
   Check, Error Log, the counts unchanged, and the smoke assertions in
   `scripts/org/package-upgrade-test/smoke-<package>.apex` (a new person gets a named
   household; a gift moves Total Giving; approved volunteer hours post to the total), each run
   as the admin and rolled back with a savepoint.
6. With `--uninstall-check[=<key>]` (default `volunteers`; a module nothing chosen depends
   on): uninstalls it, checks it is gone, that none of its classes, objects or Core automation
   switches remain (`uninstall-check.apex`, plan Principle 3), and that Health Check and the
   Core smoke assertion still pass.
7. Deletes each org unless `--keep-orgs`, and writes the report.

After a failed step the rest of that shape is skipped and the next shape runs; the org is
still deleted.

**Managed or unlocked.** `--type` says how the packages are registered in the Dev Hub
(`sf package create` fixes that; the run checks it with `sf package list`). Default `managed`
(D-173).

| | N-1 from a git ref | N-1 from a `04t` file | Post-install |
|---|---|---|---|
| `managed` | Refused: a managed beta cannot be upgraded (or installed in production). `--promote-from` promotes each N-1 version after it is built: **promotion is permanent and needs the owner's approval**, and N must then carry a higher major.minor.patch | The ids must be released (promoted) versions | Runs on its own: each package's `postInstallScript` |
| `unlocked` | Unpromoted versions install in scratch orgs | Any versions | A post-install script runs for managed packages only, so after every install and upgrade the script calls `<ns>.BarnInstallCheck.finishSetup('<Module>')` for each package as the admin itself (`setup-n1` and `setup-n` steps) |

`--plan` prints which path applies on its "N-1 path" line.

**Before it can run** (each is a MISSING line in the readiness list, which `--plan` prints and
a real run requires to be clean before it creates anything):

- The namespace registered and set in `sfdx-project.json` (D-87), at `--from` and `--to` too:
  build only from commits after it is set.
- A Dev Hub linked to that namespace, named with `--devhub` (the CLI default is never used),
  and every package created in it (`sf package create`, by the owner) with its `0Ho` id in
  `packageAliases`.
- Each dependency with a `versionNumber` and each package's InstallHandler class named as its
  `postInstallScript`: both are in `sfdx-project.json` now and checked in CI (see "Creating
  package versions" below). For a managed upgrade, `ancestorVersion` (`"HIGHEST"`) or
  `ancestorId` on every package, which is added only after the first promoted version.
- The Apex the checks call from anonymous Apex is `global`: a subscriber org's anonymous Apex
  cannot see a package's `public` classes. The templates and `seed-sample-data.sh --namespace`
  call only Core's `BarnInstallCheck` (D-199): `runHealthCheck()` (a map of `findings`,
  `errors` and `errorFindings`), `loadSampleData()` and `finishSetup(packageKey)`, each
  delegating to the public service and allowed only to someone who may run setup. Its global
  signatures are permanent; keep it to these three. The readiness list fails only when a
  template names a class that is not in the source.
- **Owner approval for the scratch orgs.** The project's test orgs are fixed; any other org is
  approved first. A real run creates one org per shape and refuses without
  `--yes-create-orgs`, the record of that approval. It prints the count first.
- **Limits.** One scratch org per shape counts against the Dev Hub's active and daily scratch
  org limits, and building from refs creates two versions per package (40 for all 20
  packages) against the daily package version limit. Check with `sf limits api display
  --target-org <devhub>` (`ActiveScratchOrgs`, `DailyScratchOrgs`, `Package2VersionCreates`),
  and narrow with `--packages` or `--shapes`. Builds with `--code-coverage` run every test and
  take long.
- The `npsp` shape needs verified NPSP ids in `scripts/org/install-npsp.sh`; the `npc` shape
  needs a Dev Hub entitled to Nonprofit Cloud (see [Scratch orgs](scratch-orgs.md)).

**Commands.**

```
# See what a run would do (no org, no Dev Hub, no files):
scripts/org/package-upgrade-test.sh --plan --from v0.18 --to main --shapes platform,npc

# Managed, N-1 already released, N built from main, all four shapes:
scripts/org/package-upgrade-test.sh --devhub <devhub> --from released-n1.txt --to main \
  --yes-create-orgs --uninstall-check

# Unlocked, a few packages, one shape, keep the org for the manual checks (T-INST-05):
scripts/org/package-upgrade-test.sh --devhub <devhub> --type unlocked --from <ref> --to main \
  --packages giving,volunteers --shapes platform --keep-orgs --yes-create-orgs
```

`--packages` takes package keys (folder names under `packages/`) and adds what they need.

**Reading the report.** `--report <dir>` (default `test-results/package-upgrade/<run id>`,
ignored by git) gets `summary.md` and `summary.json`: one section per shape (plus `build`),
each step with PASS, FAIL or SKIP, its seconds and a detail (the `04t` id built, the
username created, the counts, or the first part of the error). `logs/<shape>-<step>.log` holds
the sf JSON of each step. Read the first FAIL in a shape: everything after it says SKIP.
Exit status 0 means every step passed, 1 means a step failed, 2 means it refused to start.
The script never prints an auth URL or token and never reads `sf org display --verbose`: from
`sf org create scratch --json` it keeps only the username.

**Checks by hand.** Install links, Module Manager's guided installs and the pages after an
upgrade are in the Testing Guide, [Installing](../testing-guide/installing.md), T-INST-05. The
plan mode itself is T-INST-04 and `scripts/ci/tests/test_package_upgrade_test.py`.

### Creating package versions

BarnCRM ships as 2GP managed packages from the first pilot, under the namespace `barn` (D-199),
registered in a Partner Developer Edition org linked to the Partner Business Org Dev Hub. Until
then `namespace` stays empty in `sfdx-project.json` and no package or version is created. The
rest of `sfdx-project.json` is ready now (D-200, N5), so setting the namespace and pasting the
package ids is all that is left:

- **Version numbers.** Every package carries `1.21.0.NEXT` (`versionName` `v1.21`), the release
  that made the project version-ready. One shared number keeps the dependency pins simple; a
  package moves to its own number only once it ships a change the others do not.
- **Dependencies** name `<that package's major.minor.patch>.LATEST`, so a build picks up the
  newest build of the package it needs. Raising a package's `versionNumber` means raising every
  pin on it; `check-namespace-readiness.py` fails until they match.
- **`postInstallScript`** names each package's InstallHandler class (`<Module>PostInstall`).
  The check fails when a package has an InstallHandler that is not named, or names a class that
  is not one.
- **`packageAliases`** is an empty placeholder. `sf package create` (the owner's step, once per
  package, in the Dev Hub) prints a `0Ho` id; paste it as `"<package name>": "0Ho..."`. The ids
  are never invented: `create-versions.sh` refuses while one is missing and prints the
  `sf package create` command for it. Version aliases (`<name>@1.21.0-1`) are not kept here;
  the run writes the `04t` ids to a file instead.
- **`ancestorVersion`** is not set until the first version is promoted. From then on each
  package carries `"ancestorVersion": "HIGHEST"`, which a managed upgrade needs (the install and
  upgrade test checks it).

**Less common metadata in 2GP managed packages (D-200, N11).** Checked 2026-11-12. The
Salesforce Metadata Coverage Report and the 2GP "Metadata Components and Attributes" page
refuse automated reads (HTTP 403), so every row below is **unverified** against the report and
rests on the packaging guide as last read by hand. Before the first `create-versions.sh` run,
open the Coverage Report for API 67.0 and tick each row; a type the report does not mark for
"Second-Generation Managed Packages" fails at version create, not at deploy.

| Type (shipped in) | Expected in 2GP managed | Notes to confirm |
|---|---|---|
| `Group` `Programs_Participants` (programs) | Yes | Packaged as a public group; members are subscriber data, never packaged |
| `PlatformEventSubscriberConfig` (core) | Yes | It names no running user (only the batch size), which is what lets it install |
| `Prompt` in-app guidance, 3 (core) | Yes | In-App Guidance prompts, not Prompt Builder templates; none of the GenAI types ship |
| `ExternalCredential` `Barn_Org_Connection` (core) | Yes | Principals and their credentials are set per org after install; check the principal-access permission set entries survive packaging |
| `CustomNotificationType`, 3 (core, corporatehub, scholarships) | Yes | |
| `ContentAsset`, 9 (8 packages) | Yes | Asset files; check the subscriber can still use them after an upgrade replaces the file |
| `GlobalValueSet` (projects) | Yes | Values added by a subscriber stay; values removed in an upgrade are not removed from the org |
| `ApexPage` `FormsPublic` (forms) | Yes | Its name gains the prefix (`barn__FormsPublic`): the admin guide's Site setup step must name the page as the org shows it |
| `RemoteSiteSetting`, 6 (addressverification, funders, payments) | Yes | Subscriber may deactivate; the callout then fails with the Error Log entry, not silently |

**The script.** `scripts/packaging/create-versions.sh` builds one version of each chosen package
in dependency order, read from `sfdx-project.json` through `package-upgrade-helper.py` (the
reader the install and upgrade test uses). It prints the Dev Hub's `Package2VersionCreates`
limit first, refuses (exit 2) while the namespace is empty, a `0Ho` id is missing or fewer
creates are left than it needs, and **never promotes**: promotion is permanent and the owner's
decision, one `sf package version promote` per version. It writes `<key> <04t id>` lines to
`test-results/package-versions/<run id>.txt`, the file `package-upgrade-test.sh --from/--to`
takes.

```
# What would be built, in what order, with which commands (no org, no Dev Hub):
scripts/packaging/create-versions.sh --plan --devhub <pbo-devhub>

# Build Core and Giving (and Rollup Builder, which Giving needs):
scripts/packaging/create-versions.sh --devhub <pbo-devhub> --packages giving
```

`--no-code-coverage` skips the test run, but a version built that way can never be promoted.
`scripts/ci/tests/test_create_versions.py` runs the plan mode and the refusals.

### Global and namespace-accessible API

Once a managed version is promoted, a `global` signature can never be removed or changed, and
an `@NamespaceAccessible` one is what every other BarnCRM package compiles against: a module
installed at an older version breaks when Core drops one. So the rule is **deprecate for one
release, never remove**: mark the member `@Deprecated` (for `global`) or say so in its doc
comment, stop calling it, and keep it working. Keep the `global` surface small (today `BarnInstallCheck`,
the invocable actions, the REST resources, `InboundGift` and Rollup Builder's `RollupApi` and
`RollupInstantTrigger`).

`scripts/ci/check-api-surface.py` (D-200, N8) lists every `global` and `@NamespaceAccessible`
signature in packaged Apex in `scripts/ci/api-surface.txt`, one `<package>/<file> |
<signature>` line each (annotations, parameter names and bodies left out; a type is its
access, `virtual` or `abstract`, kind and name). It fails when a snapshot line no longer
matches the source (removed or changed), and when the source has a signature the snapshot
lacks. For an addition, run `python3 scripts/ci/check-api-surface.py --update` and commit the
snapshot with the change; it refuses while anything was removed. A removal the owner approves
before the first promoted version is made by editing the snapshot by hand in the same pull
request, so the reviewer sees it. Integrators: after merging branches that each added
signatures, run `--update` once on the landing branch.

### Tests survive an org's own customizations

BarnCRM installs as source with no namespace, so its tests are the org's local tests: they run
in a production install and in every later production deploy the organization makes, beside
the org's own validation rules, required fields, duplicate rules, flows and other packages'
triggers on Account and Contact (architect review RT-02). The shared test data
(`TestDataFactory` and the household, address and relationship factories built on it) handles
what a test can:

- **Duplicate rules:** `TestDataFactory.pastDuplicateRules(record)` saves past them.
- **Required fields:** the same call fills every custom field the org requires (not nillable,
  createable, no default) that the test left empty, with a plain sample value by type, through
  `TestDataFactory.fillOrgRequiredFields`. A value the test set is kept; standard fields and
  person account (`__pc`) fields are left to the test.
- **Access:** tests run as a user they create (below), so the org's profiles and permission
  sets do not decide the result.

**The rule:** a test class never inserts a bare `new Contact(...)` or `new Account(...)`. Build
the record through the factories (`HouseholdTestDataFactory.newContact`, `newHousehold`,
`RelationshipTestDataFactory`, `AddressTestDataFactory`, `AccountKindsTestData.organization`),
or wrap a record you build by hand, with the field values the test's assertions rely on, in
`TestDataFactory.person(new Contact(...))`, `TestDataFactory.organization(new Account(...))` or
`TestDataFactory.household(new Account(...))`. Each returns the same typed record, saved past
duplicate rules with the org's required fields filled. A bare `new Contact(Id = ...)` used to
update a row is fine (it sets no required field).

`scripts/ci/check-test-data-factory.py` (part of `run-offline-checks.sh`) counts the bare
constructions in test classes, outside classes named `*TestData` or `*TestDataFactory`, and
fails when the count rises above its `BASELINE`. A construction that must stay raw (an
in-memory record never saved, a test of the factory, a test that must exercise a raw insert)
carries `// factory-ok: reason` on the line with `new Contact(` or `new Account(`; lower
`BASELINE` whenever the count falls (`--list` prints every counted line).

What no test can handle, so the install guide and pre-check report it instead: an active
validation rule (Apex cannot skip one), a required lookup field (no sample record to point
at), and an org's own record-triggered flow or trigger that fails.

### Tests run as a user they create

From API version 67.0 a query or DML statement with no access mode runs in user mode, and
that includes the plain `insert` and `[SELECT ...]` in a test class. A test that runs as
whoever deploys or runs it passes only where that person already holds the BarnCRM
permission sets. The gate above used to assign them, so the gate alone never showed the problem; a
check-only deploy to a real sandbox, as an administrator without them, failed 565 of 1008
Core tests ("fields being inaccessible", "No such column", "Record Type ID: this ID value
isn't valid for the user", "You need the Manage BarnCRM Settings permission"). A subscriber
running the tests, or a different administrator, would see the same.

So every test is self-contained:

- Every `@IsTest` method and every `@TestSetup` method runs its body inside
  `System.runAs(TestUsers.admin())` in Core, and `System.runAs(TestUsers.adminWith('Giving_Admin'))`
  in Giving and Mirror. `TestUsers` (Core, `@IsTest`, namespace accessible) creates a user
  on the running user's own profile and assigns the packaged permission sets by their bare
  name, preferring the ones in this package's namespace. `withPermissionSets(names)` takes any
  other list. It keeps one user per list of sets per transaction, and finds the user a
  `@TestSetup` made again in every test method, so setup data and the test share an owner.
- Each test method is a transaction of its own, so a user made only inside test methods is
  inserted again, with its permission set assignments, in every one (about 330 ms each,
  roughly 7.5 minutes of a gate run before this was fixed). A class whose test methods use
  a `TestUsers` user in more than one method creates it once in a `@TestSetup`; when there
  is no other setup, that is a method whose body is just the call, such as
  `TestUsers.admin();`, and it needs no `runAs`.
- A Core test whose code calls into whichever modules are installed (the sample data loader
  counts and removes each module's records) runs as `TestUsers.adminWithInstalledModules()`:
  BarnCRM Admin plus the admin permission set of each module the org has, and `admin()` in
  an org with Core alone.
- The profile stays the running user's so a test keeps what an administrator's profile gave
  it before (View All Data over Giving's Private objects, Manage Users for the tests that
  create people) and loses only the dependence on permission set assignments. A test that has
  something to prove about least privilege still builds its own user with
  `TestDataFactory.createUser` on the Standard User profile, inside the outer `runAs`.
- A real org's System Administrator profile may hide optional standard fields (a sandbox of
  a production org had no field access to `Account.AnnualRevenue`, `Contact.Description` or
  `Contact.AssistantName`), and 55 tests that insert or query them failed with "fields being
  inaccessible" or "No such column". So `TestUsers` also builds a permission set in the test,
  once per transaction, granting Read and Edit on the optional standard fields the suite
  uses (`OPTIONAL_STANDARD_FIELDS`), and assigns it to the users on the running user's
  profile (`admin()`, `adminWith`, `withPermissionSets`, `onRunningProfileWith`) and to
  `TestDataFactory.createUser` users. The `standardUser*` helpers and `peopleReaderWith` never
  get it, because their tests prove least privilege. A test that uses a new optional standard
  field adds it to the list rather than relying on the org's profile.
- No user is given the Household record type (ADR-0141), and a plain `insert` under
  `System.runAs` checks the running user's record types, so it refuses a household with
  "Record Type ID: this ID value isn't valid for the user". Test data inserts households with
  `Database.insert(household, AccessLevel.SYSTEM_MODE)`; a test of what a person may create
  uses `HouseholdTestDataFactory.insertHouseholds` (BarnCRM's own `HouseholdWriter` path).
- Users and permission set assignments are setup objects. `TestUsers` writes them in a
  context of their own; a test that creates more people does the same with a nested
  `System.runAs(new User(Id = UserInfo.getUserId()))`, as before.
- A test that touches no data and no permission dependent code (a parser, an in-memory
  calculation) may run as the deploying user, and says so with
  `// runs-as: deploying user (reason)` above the class, or inside one method.
  `scripts/ci/check-tests-run-as.py` fails the build on any other test method without
  `System.runAs`.

The gate is the proof that a branch is self-contained: it assigns no permission set, so it
runs the tests as whoever starts it, and that user should hold none of the BarnCRM, Giving or
Mirror permission sets. On `barn-core` the running user holds none. If you hold them in your
own org, remove them (or run as a user who lacks them), so the run shows what a subscriber's
administrator would see.

### Relevant tests

The incremental gate selects tests with `scripts/org/select-org-tests.py` (see "The incremental
gate" above). A name match finds the tests that call a changed class directly, but not a test
that reaches it through a trigger, the automation registry or `Type.forName`. Two class-level
`@IsTest` parameters (API 66.0, introduced for Salesforce's `RunRelevantTests` level, which the
gate no longer uses) close that gap, and every test class carries one:

- `@IsTest(testFor='ApexClass:HouseholdService, ApexClass:HouseholdMergeService')` runs the
  class whenever one of the named classes (or `ApexTrigger:Name`) changed. It adds to what the
  name match selects; it never narrows it. Name the classes the test exercises, not
  every class it touches on the way.
- `@IsTest(critical=true)` runs the class on every incremental gate, whatever changed.
  Five classes carry it, one smoke test for each core path: `SettingsControllerTest` (settings
  console save), `HouseholdServiceTest` (a new person gets a household), `GiftRealTimeRollupTest`
  (a saved gift moves its totals), `ImportProcessorBatchTest` (an import commit) and
  `FindControllerTest` (Find and export). Together they take about 110 seconds of the full run's
  35 minutes. Add another only for a path that has to be proven on every change, since each one
  runs every time.

A test class with neither, because no Apex change should select it (a test of validation rules
or of a test utility), is listed in `scripts/ci/test-relevance-cross-cutting.txt` with its reason.
`scripts/ci/check-test-relevance.py` (static check 16) holds every new test class to this, and
fails when a `testFor` names a class or trigger that is not in `packages/`, so a rename cannot
leave a test pointing at nothing. Test utilities with no test method (`TestDataFactory`,
`TestUsers`) are skipped. The vendored rollup engine is outside the check.

### `org-tests`

Runs only on manual `workflow_dispatch`, after `static` succeeds, against the one long lived
org described above. It used to run on every push to `main` too. Now that the gate above has
already run the full suite on the same commit before it could merge, that second run only
cost CI minutes, so it is kept for a deliberate check against the secret's org. It
authenticates from `SF_TEST_ORG_AUTH_URL`, prints how many days that org has left, prints
which shape the org actually is (`scripts/org/report-org-shape.sh`, which asks the org for
the same five facts `OrgShapeDetector` reads, through the Tooling API so it works before the
packages deploy), deploys
`packages/core` and then `packages/giving`, runs the Apex tests, and uploads the results. It
creates nothing and deletes nothing.

**What the org actually is, read from the org on 2026-09-08:** Enterprise Edition, Person
Accounts yes, Sales Cloud yes, NPSP no, Nonprofit Cloud no. So it is the
`person-accounts.json` shape, which is what the setup steps above recommend and the closest
an ordinary Dev Hub gets to the Agentforce Nonprofit orgs the first customers run.

That is the good news and the caveat in one line. **The Platform-only shape is never
exercised**, and ADR-0013 makes running on a Platform-only org a requirement rather than a
preference. This org has Sales Cloud and Person Accounts, so a Core component that
accidentally depends on either would deploy here and pass here, and fail at the first
customer who has neither. `scripts/ci/check-standard-objects.sh` is the only thing standing
between the package and that mistake, and it is a grep. Testing the Platform-only shape
means a second org and a second secret; until then, treat every green org test as evidence
about one shape and no other.

The deploy goes in stages through `scripts/org/deploy-packages.sh`: Core (one stage per object under `packages/core/main/default/objects`, then
custom metadata, then labels, then static resources with custom permissions, then Apex, then
flows, then everything that wires the two together: permission sets and groups, layouts, flexipages,
applications, tabs, quick actions, Lightning components), then Giving, then Volunteers (a no-op while `packages/volunteers` holds
no metadata, and left out by `--core-only`), then Programs (left out by `--core-only`), then Logic Models (left out by `--core-only`), then Funders (left out by `--core-only`), then Mirror, then Mirror for Giving. A failed stage asks the
org for the component level report, by job id, in human form and then as JSON. Once Core's last
stage is in, the script runs `CorePostInstall.runAsSourceDeploy()` as anonymous Apex: the steps
Core's install handler runs, which a deployment never triggers (first-run setup on a fresh org,
the Automation switches, the import templates, the recommended coexistence mode, the hourly tab
access check, and the BarnCRM Admin permission set for the person deploying). It is safe on an
org that already has BarnCRM: an org with saved BarnCRM Settings or a household is treated as an
upgrade, so no setting, feature or edition an administrator chose changes, and a second run
changes nothing. `run-org-tests.sh` sets `SOURCE_POST_INSTALL=0` to skip it, because the Apex
tests assume an org that has never saved BarnCRM Settings. After the last
stage the script runs
`RollupService.ensureDefaults()` as anonymous Apex, because a source deployment runs no
post-install script and would otherwise leave the org without the rollup definitions a real
install creates (ADR-0029). It then runs `TabAccessService.requestSync()` the same way, so the
tool tabs, which live only in the `BarnCRM_Tab_*` permission sets, reach users without waiting
for the nightly sync. Unless `--core-only` is given (and `SOURCE_POST_INSTALL` is not 0, which the test gate sets, because the Apex tests assume an org with no funds) it also runs each deployed module's `runSetup` (`RollupsPostInstall`, `GivingPostInstall`, `VolunteersPostInstall`, `MirrorPostInstall`), exactly the steps its install runs (Giving's among them create the starting General Fund when the org has no fund and no default fund set), each recording the module in the setup marker `Modules_Setup_Run__c` so Health Check offers no Finish Setup there (FS1). Unless `--core-only` is given it then queues `ModuleAccessSyncs.requestAll()`,
which gives every module's permission sets to the BarnCRM roles its catalog row names (ADR-0125 D2, ADR-0131, D-200 S1). Before the first stage the script fails if a folder under
`packages/core/main/default` is named by no stage: Core's flows were never deployed until
2026-10-13 because no stage named `flows`.

That is not tidiness. The first deploy this project ever attempted sent all 982 components in
one request and came back with `UNKNOWN_EXCEPTION`, zero components deployed, zero component
errors, and a Salesforce ErrorId. A failure with nothing attached to it tells you nothing
about which of 982 things caused it. In stages, the same failure names a stage. The order also
matches how the packages depend on each other: Giving depends on Core.

An `UNKNOWN_EXCEPTION` with zero component errors is a Salesforce side failure rather than
something wrong with a component. Quote the ErrorId to Salesforce support.

**Stalled deploys (2026-09-24).** From about 13:00 UTC, on oi-test, one stage per run (a
different one each time) left its DeployRequest in Status Pending with a null StartDate. The
blocking `--wait 30` then timed out (`ClientTimeoutError`) and failed the gate; the org was
also reporting "Too many concurrent Apex compilations during resource mitigation".
`sf project deploy cancel` reported Canceled, but the tooling DeployRequest stayed Pending, and
about ten such requests remain there. Resubmitting the same stage deploys normally. So each
stage is now submitted with `--async` and followed with `sf project deploy report` every
`POLL_SECONDS` (5; 15 before 2026-10-28): a job still Pending with no start after `STALL_SECONDS` (300) is logged
as `STALLED DEPLOY`, cancelled (best effort) and resubmitted once. A second stall fails the
stage, naming both job ids. A job that has started is not a stall and keeps the 30 minute
limit (`DEPLOY_WAIT_MINUTES`). Component errors are reported exactly as before. The script
prints how many stalls it recovered before "Every stage deployed".

Two client side faults were seen the same day and are handled too. A single report call hung
for about 290 seconds on oi-test while its deploy finished in 2, so every report call is
abandoned after `REPORT_TIMEOUT_SECONDS` (60). A stage on oi-pa failed on `Error (10): fetch
failed` while the org reported that deploy Succeeded, so a transient client error (fetch
failed, `ECONNRESET`, `ETIMEDOUT`, socket hang up, a 5xx) on a submit or a report is retried
after a short backoff and never taken as a result. After a submit error, the newest
DeployRequest created in the last minute is followed if there is one (the org lock means it
is ours), so a stage is never deployed twice; otherwise the stage is resubmitted, up to three
submits. Twenty unreadable reports in a row (`REPORT_FAILURE_LIMIT`) fail the stage.

**Resolved 2026-09-22: the cause was in our files, not the platform.** 146 of the custom
metadata records wrote `xsi:type="xsd:string"` (and `xsd:boolean`, `xsd:double`) without
declaring the `xsd` prefix on the root element. The metadata API rejects such a record while
parsing, before any component is examined, and reports it as `UNKNOWN_EXCEPTION` with zero
component errors. Deploying each custom metadata type on its own with the prefix declared
(run 170 on `experiment/cmdt-by-type`) got past "Preparing" for the first time and reported
ordinary component errors instead: 16 labels over the 40 character limit and one label given
as an attribute. The next stage then named 44 custom labels whose short descriptions ran past
80 characters. All are fixed, and `check-custom-metadata.py` and `check-labels.py` now fail on each
of these before a deploy is attempted. The history below is kept because the size theory it describes
was wrong, and the way it was wrong is worth remembering: a failure with no component errors
can still be a defect in a component, when the defect stops the file being read at all.

**It is not transient here, whatever the general advice says.** This failure came back four
times across four separate runs before 2026-09-09, always on the Core stage, always with zero
components deployed and zero component errors, and always with the same trailing code in the
ErrorId (`-315522575`) behind a different leading number each time. It then hit that same
undivided Core stage twice more on 2026-09-09, on two separate pushes to main, once at 904
components. A three-way split (data model, Apex, UI and permissions) went in immediately
after, to see whether a smaller request avoided it. The very next run failed again, on the
data model stage alone, at 853 components: close enough to 904 and 982 that a specific bad
file stopped being the likely explanation. Three deploys of substantially different content
(mostly Apex the first two times, mostly custom fields and their sub-components the third)
failing in the same shape once each got into the same few-hundred-to-thousand range reads as
a size effect rather than a component defect, though nothing about this failure can be
proven from the client side, so treat that as the working theory, not a settled fact.

Ten occurrences, none resolved by re-running: six identical failures on Core (four documented
before 2026-09-09, two more that day), the data-model stage's failure right after the first
split, a further one after that, the config stage's failure once objects had been cleared, and
custom metadata's failure alone once config had been split three ways. `scripts/org/deploy-packages.sh`
now prints only the component failures on a failed stage, and points at the resolution above.

The data model stage was then split again, into two runtime-balanced halves of
`packages/core/main/default/objects` plus a third stage for custom metadata and the remaining
data-model metadata types. That halving is what stopped being useful evidence: across four
consecutive pushes, all fixing real component-level errors the org had newly started
reporting (list view defects, not deploy-shape ones), the same 10-object, 139-file half kept
failing with the zero-component `UNKNOWN_EXCEPTION` every single time, while the other
11-object, 144-file half deployed clean every one of those four runs. Both halves stayed the
same size and the same content across all four runs, because `balanced_split` only reacts to
file *counts*, which never changed; only file *content* did. Two comparably sized groups
behaving oppositely and consistently four times running is evidence against a size effect,
not for one: it points at something specific to one or more objects inside the failing half,
not at the request being too big.

Objects now deploy one at a time, each its own stage, rather than another same-content
halving that would only repeat the last four results. That worked immediately: every object
deployed clean on the next run, and Address__c's own two real component errors (an invalid
`length` on a `TextArea` field, and that same field listed in a compact layout, which no text
area field may be) turned out to be what the opaque failure had been hiding on that object,
not the platform fault recurring.

With every object clear, the fault moved to the next stage in line: the four config
directories (custom metadata, labels, static resources, custom permissions), deployed
together, hit it at 568 components. File count badly misled here: roughly 70 files across all
four looked nowhere near a risk, but `packages/core/main/default/labels/CustomLabels.labels-meta.xml`
is one file holding 388 individual label components, each one its own component for deploy
purposes. Config was split into three stages: custom metadata alone, labels alone (isolating
that one file), and static resources with custom permissions together, since both are a
handful of components on any count.

Custom metadata alone, about 60 records, failed the same way, confirmed identical on a manual
re-run: same zero components, zero errors, same ErrorId trailing code. This is the point where
size stops being a workable explanation for the occurrence in front of us: 61 files is nowhere
near the few-hundred-to-thousand range every prior failure carried, and it is the first time a
stage this small has failed on its own. The working theory shifts from request size to request
*rate*: every stage in this script is its own blocking deploy call, run immediately after the
previous one reports done, against the one persistent org, with no gap between them. If the
org's deploy engine needs a moment after a deploy completes before it can safely accept the
next one, back to back calls would reproduce exactly this. Untested and not the only remaining
explanation, but cheap and non-destructive to try: every `deploy_stage` call paused (15
seconds, `STAGE_PAUSE_SECONDS`) after a successful deploy, before the next stage started. The
pause is now off by default: see "Faster deploys" below. Apex and UI/permissions are unchanged, because neither has failed yet.

**If a stage fails again, keep the pattern rather than guessing at a safe size.** Read
`scripts/org/deploy-packages.sh`'s own header, which is updated at each split with what the
run actually showed, split whichever stage actually failed the same way (narrower, on what
that stage carried, not a round number picked in advance, and never just another same-size,
same-content split of a stage that has already failed that way more than once), and update
both this section and that header with the new count before pushing. Guessing a threshold and
pre-splitting everything to be safe is not the goal: each split should answer a question the
previous failure actually raised.

**Faster deploys: the fast settings are the defaults.** The stages cost about 36 requests,
each followed by a 15 second pause: about 9 minutes of sleep per run before any submit or poll
time. Both faults that drove the splitting were later traced to real defects (the Account to
`Import_Batch__c` order, now computed, and the unparseable custom metadata resolved on
2026-09-22), so neither the pause nor the per-object split has evidence behind it any more.
The full gate with both dropped took about 12 minutes end to end on oi-test on 2026-10-13,
clean, so both are now the defaults:

- `STAGE_PAUSE_SECONDS` defaults to 0: no pause between stages. Set it (for example to 15) to
  bring the pause back.
- `DATA_MODEL_STAGES` defaults to `combined`: every Core object in one request. If that request
  fails with component errors, the run stops as usual. If it fails with none (the opaque
  `UNKNOWN_EXCEPTION`), the script falls back to one object per stage in the same run.
  `DATA_MODEL_STAGES=per-object` always deploys one object per stage.
- `POLL_SECONDS` defaults to 5 (batch testing, 2026-10-28). At 15, a stage of a handful of
  components finished in a few seconds but was not seen as done until the first report, so
  each of the twelve stages cost at least about 17 seconds.
- `DEPLOY_SHOW_COMPONENTS` defaults to 0: a stage that succeeded is no longer followed by a
  second report call listing every deployed component (one more CLI round trip per stage and
  about 1 MB of log per run). Set it to 1 to bring the list back. A failed stage still prints
  its full report and its component failures.

- `CONFIG_STAGES` defaults to `combined` (2026-10-28, D-141 amendment): Core's custom metadata,
  labels, static resources, custom permissions and notification types in one request, falling
  back to the three old stages only when it fails with no component error. `separate` always
  uses the three stages.
- `MODULE_STAGES` defaults to `combined` (2026-10-28): Rollup Builder, Giving, Volunteers (when it
  holds metadata), Mirror and Mirror for Giving in one request, falling back to one module per stage, in dependency
  order, only when it fails with no component error. `separate` always deploys one per stage.

If the opaque fault comes back, run with `STAGE_PAUSE_SECONDS=15 DATA_MODEL_STAGES=per-object
CONFIG_STAGES=separate MODULE_STAGES=separate` and record in this section and the script header
what the run showed.

**Skipping unchanged packages (2026-10-28, D-141 amendment; D-56 allows "deploy only changed
metadata").** A package whose source is identical to what the last successful
`deploy-packages.sh` run put in the same org is not deployed again. Its Apex still deploys
(`DEPLOY_APEX_ALWAYS=1`, the default), because the release gate's coverage check relies on the
deploy recompiling every class; the incremental gate checks no coverage and passes 0.

- **Where the record lives:** one JSON file per org, named by the org id, in
  `~/.local/state/barncrm/deploy-state/<org id>.json` (`DEPLOY_STATE_DIR` to change it). It is
  outside every repository and worktree, so every gate worktree on the machine shares it and a
  fresh worktree does not lose it. It holds the org id, the git tree id of each deployed
  package, a fingerprint of `sfdx-project.json`, `.forceignore` and `scripts/org`, and the id of
  the org's newest `DeployRequest` when the run finished.
- **Any doubt means a full deploy:** no record, an unreadable one, or one for another org id; a
  changed fingerprint; a `DeployRequest` in the org newer than the recorded one (anyone deployed
  anything since, from any machine or branch); uncommitted or untracked files under `packages/`
  or the deploy inputs; or `--full` (`DEPLOY_FULL=1`; `run-org-tests.sh --full-deploy`).
- **The record is deleted before the first stage** and written only after every stage deployed,
  so a run that fails partway leaves none. The incremental gate deploys nothing after the staged
  deploy (its tests run with `sf apex run test`), so the record the staged deploy wrote stands.
  `deploy-packages.sh <alias> --adopt <deploy id>` keeps a record valid after a deploy that
  resends Apex already in the org from the same commit, and only when nothing else deployed in
  between; no gate calls it now.
- **Not detected:** a change made by hand in Setup to packaged metadata. After one, run with
  `--full-deploy`, or delete the record.

`scripts/ci/tests/test_deploy_skip_unchanged.py` (run by `Static checks`) drives these rules
with a fake `sf`.

Two things constrain when it runs, both because there is one org rather than one per run.

It runs **on a push to `main`, or on a manual run** from the Actions tab (Run workflow), which
is how to retry after changing a secret without inventing a commit to do it. Deploying a pull request's code into the test org would
leave that org holding unmerged work, and the next run against main would inherit it. Pull
requests get the static checks, which is where most of the signal is.

It carries a **single global concurrency group**, `org-tests-persistent`, so two runs never
deploy at once, and `cancel-in-progress` is **false**. Cancelling a deploy partway through
would leave the org holding half a package, and unlike a scratch org that is thrown away, that
state persists into the next run. Runs queue instead; GitHub keeps only the newest waiting one.

The first version of this got the second point wrong: a global group with cancel-in-progress
set to true meant an unrelated Dependabot run cancelled main's job after every step had
already passed, which showed up as a cancelled build on a commit that was fine.

### `dco`

Checks that every commit being merged (or every pushed commit, on a push to `main`) has
a `Signed-off-by:` trailer. Merge commits are exempt. See "Signing off commits" below.

## Offline Apex checking

`scripts/ci/check-apex-offline.sh` gives feature agents compile-level feedback on Apex
without needing a scratch org or Dev Hub. It is not yet wired into `.github/workflows/ci.yml`.

It runs `CheckForIssues` from `apex-ls` (the nawforce/apex-dev-tools Apex language
server, `io.github.apex-dev-tools:apex-ls` on Maven Central) against the whole
`packages/` tree, using the repo's root `sfdx-project.json`. On first run it resolves the
jar and its dependencies from Maven Central via Maven and caches them under `.tools/`
(gitignored); later runs reuse the cache and need no network access. Requires Java 21+
and, for the first run only, Maven, both already present in the standard dev and CI
environment.

Run it from anywhere in the repo:

```
scripts/ci/check-apex-offline.sh
```

It exits non-zero if any errors are found, and prints each error with file, line, and
column. What it catches:

- Syntax errors.
- Type errors (incompatible assignment, incompatible return type, wrong argument types,
  and similar).
- References to unknown classes, methods, and variables.

What it does not catch:

- Unknown fields in SOQL queries (for example `[SELECT Missing__c FROM Thing__c]` where
  `Missing__c` does not exist passes with no error). `scripts/ci/check-field-references.py`
  covers this for BarnCRM's own objects (`static` job, check 6); fields on other objects
  still need a clean org, since the dev gate orgs keep removed fields.
- Anything that is only enforced at runtime (CRUD/FLS, governor limits, trigger order of
  execution, and so on).

## Detection-only exemptions

`scripts/ci/check-standard-objects.sh` fails the build when Core, Giving, Volunteers,
Programs, or Funders names a standard object the Platform-license floor does not have
(Opportunity, Campaign, Lead, Case), a Person Account field, or an Industries object
(ADR-0009, ADR-0013).

Detecting that one of those exists is not the same as depending on it. Core has to tell an
administrator what is installed in their org: that is the Health Check (plan Section 4.8),
and it is how the coexistence mode is recommended (plan Section 4.5). Detection is done
with `Schema.getGlobalDescribe()` and field maps, against names held in String constants,
so nothing is bound at compile time and Core still deploys on an org where those objects
are absent. The grep cannot tell the difference, so it is told explicitly.

An Apex line (`*.cls` or `*.trigger`) carrying the comment

```
// detection-only: <reason>
```

is exempt from the check. Rules:

- The marker works only in Apex, and only on the line it is written on.
- Use it on constant declarations. A constant is inert; an expression is not.
- The reason is written for a reviewer, not for the script. Say what the constant detects
  and what reads it.
- Every exempted line is printed on every run, under the heading "Detection-only
  exemptions", whether the check passes or fails. The list is meant to be read: if it grows,
  something is wrong.
- The marker does not make a compile-time reference legal. `Opportunity.Name` with the
  marker appended still stops Core deploying on a Platform-only org, and no CI check will
  catch it before the org shape matrix does.

As of v0.1 the marker appears on four constant declarations in `OrgShapeDetector` (the NPSP
namespace prefix, the Person Account indicator field, the Industries gift object, and the
standard Sales Cloud object) and nowhere else. Three of the four are printed as exemptions:
the NPSP prefix is not a name the grep looks for, and carries the marker only so that the
four detection constants read alike.

### Import template column headings

A shipped import template (`customMetadata/Import_Template_Default.*.md-meta.xml`) is exempt
as a whole file, and only that custom metadata type is. Its mapping document names the columns
of a file exported from another system, and a Data Loader export of NPSP or Nonprofit Cloud
heads its columns with that system's field paths, for example
`GiftTransaction.OriginalAmount` or `npe01__Opportunity__r.Campaign.Name`. The importer
compares those words with a file's header row as text; nothing resolves them against the
org's schema, so they bind nothing and cannot refuse a deployment. The script prints each such
file under "Import template column headings, not references" on every run. Test classes get
no such exemption: a test of a migration template reads the headings from the shipped
mapping rather than spelling them out.

The exemption is decided on the file's path, never on a line's content, so an Apex comment that
names such a path is still checked. It covers whole files, which is safe only while the type
has no MetadataRelationship field: a value in such a field is resolved against the org at
deploy time, so if the type ever gains one, revisit the exemption.

`check-namespace.sh` treats the same files the same way in its prefixed-component check,
because an NPSP export heads its columns with NPSP's own prefixed names (`npe01__`, `npsp__`).
It lists them and does not fail on them. Its pattern is anchored to the path part of each
`grep -rn` line, so a line in any other file that names such a path is still checked. Its
literal `barncrm__` check still covers them.

## What happens when the secrets are missing

The `org-tests` job checks for the secret first. If it is empty, every org-dependent
step is skipped and the job posts a `::warning::` explaining why, instead of failing.
`static` (lint, unit tests, Code Analyzer, namespace and standard-object checks) still
runs and still gates merges regardless of whether the secret is set. This means a fork
without access to the secret can still open a pull request and get useful signal; only the
live org work is skipped.

Two secrets are involved and they do different jobs. `SF_DEVHUB_AUTH_URL` lets a machine
create scratch orgs; nothing in continuous integration uses it now that the test org is long
lived, and it is kept because creating and refreshing that org needs it.
`SF_TEST_ORG_AUTH_URL` names the org the tests actually run in, and is the one `org-tests`
requires.

## Setting the `SF_DEVHUB_AUTH_URL` secret

This secret holds a Salesforce SFDX auth URL for the Dev Hub the `org-tests` job uses to
spin up scratch orgs. Only repository maintainers with a Dev Hub-enabled org should set
this.

1. Authenticate to the Dev Hub locally:

   ```
   sf org login web --alias devhub
   ```

2. Get its auth URL:

   ```
   sf org display --target-org devhub --verbose --json
   ```

   Copy the `result.sfdxAuthUrl` value from the JSON output. Treat this value as a
   credential: it grants access to the Dev Hub. Do not paste it into a file that gets
   committed, and do not paste it into chat, an issue, or a pull request.

3. In the GitHub repository, go to **Settings > Secrets and variables > Actions > New
   repository secret**. Name it `SF_DEVHUB_AUTH_URL` and paste the auth URL as the
   value.

The workflow writes this secret to a temporary file only inside the CI runner, uses it
once with `sf org login sfdx-url --sfdx-url-file`, and deletes the file immediately
afterward. The auth URL itself is never written to any file that is committed or
uploaded as an artifact.

## Reading Code Analyzer results

Every `static` run uploads a `code-analyzer-results` artifact containing:

- `code-analyzer-results.html`: a readable report, open it in a browser.
- `code-analyzer-results.json`: the same findings in machine-readable form.

Download the artifact from the workflow run's Summary page under **Artifacts**. Each
finding lists a severity (1 Critical through 5 Info), the rule, the file and line, and a
description.

### Severity threshold policy

The `static` job runs Code Analyzer with `--severity-threshold 2`, meaning the command
(and the job) fails if any finding is severity 1 (Critical) or 2 (High). Lower-severity
findings are reported but do not fail the build. The policy is zero high or critical
findings on every pull request; do not raise the threshold to make a build pass, fix the
finding or, if it is a false positive, suppress that specific rule with a documented
reason.

## Signing off commits (DCO)

BarnCRM uses the Developer Certificate of Origin instead of a CLA. Every commit must
carry a `Signed-off-by:` trailer with your name and email, certifying you have the right
to submit the change under the project's license.

Sign off a single commit:

```
git commit -s -m "Your commit message"
```

Sign off every commit on an existing branch that is missing the trailer:

```
git rebase --signoff main
git push --force-with-lease
```

Git has no built-in setting that adds the trailer to every `git commit` automatically,
but you can get the same effect with a local alias so you never have to remember the
flag:

```
git config --global alias.ci "commit -s"
```

Then use `git ci` instead of `git commit`. If you prefer, a `prepare-commit-msg` hook
that appends the trailer works too; either is fine as long as every commit ends up
signed off before it reaches CI.

The `dco` CI job checks every commit in a pull request (or every pushed commit, on a
push to `main`) for the trailer and fails with a list of offending commits and a fix
hint if any are missing.

Merge commits are the one exception: the job passes `--no-merges`, so a commit that git
wrote to join two branches is not checked. A merge commit carries no authored content,
so there is nothing for anybody to certify the origin of; the certification belongs on
the commits the merge brings in, and every one of those is still checked. The Developer
Certificate of Origin's own tooling makes the same exemption. Signing a merge anyway,
with `git merge --signoff`, is harmless and costs nothing, so integrators who want an
unbroken chain of trailers can keep doing it.

## Handoff: open work and what still needs testing

Recorded 2026-09-26, when development moved from one maintainer session to shared Claude
Code users. Everything below is pushed to GitHub; nothing lives only on a local machine.
Remove each item from this list in the PR that finishes it.

Last checked 2026-10-12: nothing below has changed since 2026-09-26. `main` is at PR #178, the
C-29 stack is still open and needs a gate run on its new top head, Dependabot #179 is merged,
and #180 is open. The plan's Section 0 carries the same build-state summary.

### Waiting to merge: C-29 neutral Core (PRs #163 to #174)

- Branches `feature/c-29-neutral-core-1` to `-12`, stacked; top head
  `ffcf5b6562c39f837578dec6f04a69bdc528d790`. Review approved. ADR-0059 is already numbered.
  That head merged `main` in on 2026-10-12 (no conflicts); the earlier head was `3da9276`.
- Not yet tested cleanly: the last `Org tests (local)` status, on `3da9276`, was `failure`. Of two
  full runs, one hit the sf CLI heap crash, and the other passed 2,234 of 2,235; the one failure
  was the flaky `DuplicateServiceTest.theStandardRuleForPeopleFindsIdenticalTwinsOnce`,
  which passed 16 times out of 16 when run alone.
- To land it:
  1. Run one full gate from a clean detached worktree at the top head, with
     `scripts/org/run-org-tests.sh oi-test` (or `oi-pa`).
     If only the flaky test fails, rerun the gate.
  2. Fast-forward each lower branch to the top head:
     `git push origin ffcf5b6562c39f837578dec6f04a69bdc528d790:refs/heads/feature/c-29-neutral-core-N`
     for N = 1 to 11.
  3. Wait for the CI checks. The jest test `setupStepFields` "opens the tab a navigation field
     names" fails about one full parallel run in five (it passes alone); if it is the only static
     failure, re-run the job once.
  4. Squash-merge the bottom PR:
     `gh pr merge 163 --squash --match-head-commit ffcf5b6562c39f837578dec6f04a69bdc528d790`.
     The stacked PRs close as merged.

### Never tested

- Core installed without Giving, in any org. Every gate run deploys all three packages.
- The Platform-only shape. Both test orgs (`oi-test`, `oi-pa`) have Person Accounts, and
  ADR-0013 notes that even a Platform-only scratch org keeps the standard objects. Only the
  static checks (`check-standard-objects.sh`) and review cover it.

### Work items

These are also recorded, in the same detail, in plan Section 11.3 (parking lot). Remove an item
from both when its PR merges. Item numbers match the plan's and are kept when an item is
removed, so a list may start above 1.

2. **Log unrecognized checkbox values in imports.** `ImportRowProcessor.convertCheckbox` reads
   only `true`, `yes` and `1` as true. The new rule:
   - **True:** `true`, `yes`, `y`, `1`, `x`, `checked`, `on`, `t`.
   - **False:** `false`, `no`, `n`, `0`, `off`, `f`.
   - **Blank:** no change.
   - **Anything else:** skip the field, with a note in the run log.

   Update the admin guide first. Add tests, including a 200-row bulk case.

### Next on the roadmap

Product plan Section 6 is the source of truth:
- **X-07 Gift Transaction mirror.** It shares `MirrorSync` with X-01.
- **v0.7 items:**
  - C-32: import matching and per-file values;
  - C-33: load one object;
  - C-34: Find query builder;
  - C-35: bulk update, which depends on C-34.

  Before C-34, the query compiler needs a security review and scale tests.

### Owner questions

The owner questions raised while building v0.5 and v0.6 are plan Section 11.2, items 14 to 27,
each with the default that shipped and a recommendation.

### Working notes for new contributors

- **Test orgs:** `oi-test` and `oi-pa` are on the maintainer's Dev Hub. A contributor who
  cannot reach them needs their own Dev Hub and org, and the maintainer's approval for any
  new org, as described earlier on this page. Both expire soon: `oi-test` on 2026-10-23 and
  `oi-pa` on 2026-10-24. Recreating `oi-pa` from `person-accounts.json` is pre-approved;
  replacing `oi-test` also means updating the `SF_TEST_ORG_AUTH_URL` secret.
- **The gate:** run it from a clean, detached worktree at the pushed head. The script checks
  for a clean tree only when it starts.
- **Staging:** stage by explicit path. A synced checkout can create untracked copies named
  like `file 2.md`.

## Scratch org snapshots

Snapshots shorten recreating a test org from a full deploy (many minutes, and the stalled deploys
described above) to creating an org from saved state. They are a local convenience: nothing in
continuous integration creates or uses one.

**Dev Hub requirements.** The Dev Hub must have Scratch Org Snapshots turned on (Setup, Dev Hub,
enable scratch org snapshots; the orchestrator confirms the exact label). Snapshot count and the
snapshot's own lifetime are limited and set by Salesforce; check the current values with
`sf org list snapshot` and Salesforce's scratch org snapshot documentation before relying on a
snapshot older than a few weeks. The source org must be an active scratch org of that Dev Hub.
A snapshot cannot be created from an org that is not a scratch org.

**Commands.**

```bash
scripts/org/create-snapshot.sh oi-pa BarnPA              # snapshot an existing org (refreshes if BarnPA exists)
scripts/org/create-org-from-snapshot.sh person-accounts oi-pa --days 7 --replace
scripts/org/create-org-from-snapshot.sh platform-only barn-core --days 7
sf org list snapshot                                      # status and names
```

**Owner approval.** Creating a snapshot and creating any scratch org need the owner's approval.
Pre-approved without asking: recreating `oi-pa` or `barn-core` (expires 2026-10-15) when it
expires. Replacing `oi-test` also means updating the `SF_TEST_ORG_AUTH_URL` secret, because the
new org has a new auth URL.

**When to refresh.** After any change under `packages/` that the next test run needs (a snapshot
does not track the repository), after the Dev Hub or the Salesforce release changes the shape,
and before the snapshot's own expiry. The script warns when `packages/` changed after the
snapshot date. Sample data is seeded into the source org before the snapshot, so it carries over.

**After creating an org from a snapshot,** run `scripts/org/run-org-tests.sh <alias> --release` once and
check the shape line it prints, as for any new org.
