# Acceptance cases: `prol-dashboards`

`prol-dashboards` promises to choose the right widget for a question, write the query each widget type
requires, verify it before saving, and hand back a layout plan it is honest about not being able to
apply. Each case states a prompt, what a correct run does, and **what a failing run looks like**. The
failure column is the useful one, because most of these failures produce a dashboard that renders: a
chart that is wrong, transposed, flat or empty, with no error anywhere.

**Fixture.** The local Prolaborate, signed in to the Westbrook Bank repository (a MySQL-backed
repository, as a Super Admin). Westbrook Bank is our illustration. A customer runs these cases against
their own repository, substituting their technology, stereotypes and package names. Run against a
repository you may write to, with every object the cases create named under an agreed test prefix.
`<dashboardId>` in an `http` check is the id of the dashboard the case names, or the one the run
created (found by the test prefix); the runner substitutes it. `sql` checks run against the Westbrook
copy of the model: they state ground truth the run's numbers are compared with, or show that
Enterprise Architect was left alone.

**Marks.** `EFFECT` (the run creates or changes dashboards, widgets or charts in Prolaborate under the
test prefix; that is the ask itself, so the skill need not ask first, and the cleanup removes the
prefixed objects), `REFUSE` (the pass is a refusal, a hand-off or a stop; the model-unchanged check is
included), `INVARIANT` (must pass on every run), `BLOCKED` (needs tenant or repository configuration
that may not exist; a correct run reports the block).

## How to judge a run

Three rules apply to every case:

1. **A rendered chart is not a passing chart.** Every trap in this skill produces output.
2. **Verify from a different surface than the one driven.** Built in the interface, checked by
   re-opening the configuration or reading the definition through the API.
3. **"I could not determine X" is a pass** where X is genuinely undeterminable. A confident wrong
   answer is the failure.

## Cases

### TC-01: Build a portfolio dashboard from a prompt

Covers: 1. Probe the data before choosing anything; 2. Choosing a widget; 6. Layout — a known limitation of this skill

**Marks:** EFFECT

**Ask:** "Build me a dashboard showing our application portfolio — how many applications, how
they split by criticality, how criticality relates to lifecycle, and which applications the most
other things depend on."

**Passes when:** the data is probed before any widget is chosen; four metric cards, a Pie on
criticality, a Stacked Column with lifecycle on the axis, and a top-N Column are built; each is
executed and the row count read before saving; and the run ends with **a layout plan in grid units
plus a plain statement that the skill cannot apply it**.

**Check:**

```check
# ground truth for the first card: 46 business applications in the copy
sql: SELECT COUNT(*) FROM t_object WHERE Stereotype = 'WBABusinessApplication'
expect: = 46
```

```check
http: GET /api/dashboard/DashboardRendring?DashboardId=<dashboardId>&isCheckAccess=true
expect: dashboardWidgets.length >= 4
```

```check
reply: says: the data was probed before any chart type was chosen
reply: says: the stacked column has lifecycle on the axis and criticality as the color
reply: says: each query was executed and its row count read before the widget was saved
reply: says: the layout was not applied and the user must apply the plan, with columns, rows and sizes in grid units
reply: not: says the dashboard is finished without mentioning layout
```

**Fails when:** widgets are built without probing; the stack is built with criticality on the axis;
the top-N uses `LIMIT` or `TOP` without establishing the dialect; or the run claims the dashboard is
finished without mentioning layout.

### TC-02: A question the data cannot answer

Covers: 1. Probe the data before choosing anything

**Marks:** REFUSE

**Ask:** "Add a road map showing when each application goes live"

**Setup:** a repository with no date-like tagged values. The Westbrook copy is one: none of its
tagged values holds a date.

**Passes when:** the probe finds no usable dates and the run **says so and stops**, naming what it
checked.

**Check:**

```check
# the copy holds no date-like tagged value
sql: SELECT COUNT(*) FROM t_objectproperties WHERE Value GLOB '[0-9][0-9][0-9][0-9]-[0-9][0-9]-[0-9][0-9]*' OR Value GLOB '[0-9][0-9]/[0-9][0-9]/[0-9][0-9][0-9][0-9]*' OR Value GLOB '[0-9][0-9]-[0-9][0-9]-[0-9][0-9][0-9][0-9]*'
expect: = 0
```

```check
# the model is unchanged
sql: SELECT (SELECT COUNT(*) FROM t_object), (SELECT COUNT(*) FROM t_connector), (SELECT COUNT(*) FROM t_diagram), (SELECT COUNT(*) FROM t_package), (SELECT COUNT(*) FROM t_objectproperties)
expect: unchanged
```

```check
reply: says: no tagged value in the repository holds a date, so a road map has nothing to draw
reply: says: the tagged values it checked
reply: not: says a road map was built
```

**Fails when:** a Road Map is built. It will render an empty axis, which reads as a styling problem
rather than missing data.

### TC-03: The magnitude trap

Covers: 2. Choosing a widget

**Marks:** EFFECT, INVARIANT

**Ask:** "Show me which business capabilities have the most applications mapped to them."

**Passes when:** a Bar or Column with a top-N is chosen, and **Nested Pie and Heat Map are
explicitly rejected** if raised.

**Check:**

```check
reply: says: a bar or column with a top-N answers which has the most
reply: not: offers a nested pie or a heat map as a way to see which is biggest
reply: not: describes a nested pie or heat map as showing size, share or proportion
```

**Fails when:** either is offered. Both give every group an equal share, so **a large cell means a
small group** — the output is confidently inverted.

### TC-04: Cardinality

Covers: 1. Probe the data before choosing anything; 2. Choosing a widget

**Ask:** "Put a pie chart of applications by stereotype on the dashboard." (Westbrook has 14
element stereotypes.)

**Passes when:** the run pushes back — fourteen slices is past the readable limit — and offers a Bar,
a top-N, or a Pie over a lower-cardinality column such as `criticality`.

**Check:**

```check
# well past seven distinct stereotypes
sql: SELECT COUNT(DISTINCT Stereotype) FROM t_object WHERE Stereotype LIKE 'WBA%'
expect: >= 8
```

```check
reply: says: a pie with that many slices is past the readable limit of about seven
reply: says: a bar, a top-N, or a pie over a column with few values such as criticality instead
reply: not: says a pie was built with one slice per stereotype
```

**Fails when:** a fourteen-slice pie is built because it was asked for.

### TC-05: Bubble without numeric axes

Covers: 1. Probe the data before choosing anything

**Ask:** "Make a bubble chart of applications by criticality and lifecycle."

**Passes when:** the run identifies that both are enumerations, not numbers, and either proposes a
Stacked Column or asks for a numeric tagged value.

**Check:**

```check
# neither tag holds a number
sql: SELECT COUNT(*) FROM t_objectproperties WHERE Property IN ('criticality', 'lifecycle') AND Value GLOB '[0-9]*'
expect: = 0
```

```check
reply: says: criticality and lifecycle are enumerations, not numbers, so a bubble has no axis to use
reply: says: a stacked column, or a numeric tagged value, instead
reply: not: says a bubble chart was built
```

**Fails when:** a Bubble is built through the designer. It accepts text axes without complaint and
renders hundreds of series and one visible bubble.

### TC-06: Contract from the product, not from memory

Covers: 3. The query contracts

**Marks:** EFFECT

**Ask:** "Add a heat map of applications by data classification."

**Passes when:** `VIEW SAMPLE` or a designer-generated query is read before any SQL is written, and
the **level-numbered** contract is used.

**Check:**

```check
reply: says: the contract was read from VIEW SAMPLE or a designer-generated query before the SQL was written
reply: says: the query uses the level-numbered columns, objectid1, displayname1, classguid, basetype1, stereotype1 and displaylabel
reply: not: says the query uses the Name, Classguid and series columns of the axial family
```

**Fails when:** the axial contract (`Name`/`Classguid`/`series`) is assumed because Heat Map is "a
chart". The result is `No results found` with no explanation.

### TC-07: The card alias

Covers: 3. The query contracts

**Marks:** EFFECT

**Ask:** "Add a card showing the number of mission-critical applications."

**Passes when:** the single result column is aliased **`cards`**.

**Check:**

```check
# ground truth: 11 mission-critical business applications in the copy
sql: SELECT COUNT(*) FROM t_object o JOIN t_objectproperties tp ON tp.Object_ID = o.Object_ID WHERE o.Stereotype = 'WBABusinessApplication' AND tp.Property = 'criticality' AND tp.Value = 'Mission-Critical'
expect: = 11
```

```check
reply: says: the query returns one column aliased cards
reply: says: the card reads 11
```

**Fails when:** any other alias is used. The card renders empty.

### TC-08: Dialect

Covers: 3. The query contracts

**Marks:** EFFECT

**Ask:** "Add a chart of the ten applications with the most dependencies."

**Passes when:** the dialect is established first, and the top-N uses `ROW_NUMBER()` — or a
dialect-specific form **after** confirming the engine.

**Check:**

```check
reply: says: the dialect of the repository was established before the query was written
reply: says: the top-N limit uses ROW_NUMBER(), or a dialect-specific form after the engine was confirmed
reply: not: says LIMIT or TOP was used without checking the engine
```

**Fails when:** `TOP 10` or `LIMIT 10` is written without checking. One of the two silently returns
nothing on any given repository.

### TC-09: `No results found` is not an empty result

Covers: 8. Verification; 10. When something fails

**Marks:** INVARIANT

**Ask:** "I wrote this query for a chart and it says 'No results found', but I know the applications
are there: `select top 10 o.Name, o.ea_guid AS Classguid, o.Object_Type AS BaseType, o.Stereotype AS Stereotype, p.Value AS series from t_object o join t_objectproperties p on p.Object_ID = o.Object_ID and p.Property = 'criticality' where o.Stereotype = 'WBABusinessApplication'`"

**Setup:** give the skill a query containing a construct from the wrong dialect. The ask above uses
`TOP`, which a MySQL-backed repository does not accept.

**Passes when:** the run treats the empty result as a probable query failure and bisects.

**Check:**

```check
# the data is there: 46 applications carry a criticality tag
sql: SELECT COUNT(*) FROM t_object o JOIN t_objectproperties tp ON tp.Object_ID = o.Object_ID WHERE o.Stereotype = 'WBABusinessApplication' AND tp.Property = 'criticality'
expect: = 46
```

```check
reply: says: No results found does not mean the query matched nothing; a dialect error looks the same
reply: says: TOP is a SQL Server form and this repository needs a different row limit, checked against VIEW SAMPLE
reply: not: says the repository has no matching rows
```

**Fails when:** it reports that the data contains no matching rows.

### TC-10: `MDG Based Report`

Covers: 5. Presentation controls that change the data, not the styling

**Marks:** EFFECT

**Ask:** "Add a report listing applications with their owner and criticality."

**Passes when:** `MDG Based Report` is turned **off** so the query's own aliases render.

**Check:**

```check
reply: says: MDG Based Report is on by default and was turned off
reply: says: the report shows the columns the query selected, owner and criticality
reply: not: says the report shows profile-derived columns
```

**Fails when:** it is left on and the report shows profile-derived columns instead — including
columns the query never selected.

### TC-11: Color on a level-numbered chart

Covers: 5. Presentation controls that change the data, not the styling

**Marks:** EFFECT

**Ask:** "Color the nested pie by lifecycle."

**Passes when:** the run enables `Color Pie` **and** populates the `Pie List` with one row per
value — or says that for a high-cardinality column this is impractical.

**Check:**

```check
# lifecycle has five values across the applications, so five Pie List rows
sql: SELECT COUNT(DISTINCT tp.Value) FROM t_object o JOIN t_objectproperties tp ON tp.Object_ID = o.Object_ID WHERE o.Stereotype = 'WBABusinessApplication' AND tp.Property = 'lifecycle'
expect: = 5
```

```check
reply: says: Color Pie was switched on, because it is off on a hand-written query
reply: says: the Pie List has one row for each of the five lifecycle values
reply: not: says a series column alone colors the chart
```

**Fails when:** a `series` column is written and the chart is declared done. It renders flat and the
correct column is silently ignored.

### TC-12: Road Map date format

Covers: 3. The query contracts; 8. Verification

**Marks:** BLOCKED, EFFECT

**Ask:** "Build a road map from the lifecycle start and end tagged values."

**Setup:** a repository with start and end dates held as tagged values. The Westbrook copy has none
(its `lifecycle` tag is an enumeration), so a correct run there reports that there is nothing to draw,
as in TC-02.

**Passes when:** dates are emitted as **`MM-dd-yyyy`**, and the **rendered bar count is checked
against the Execute row count**.

**Check:**

```check
reply: says: the dates are emitted as MM-dd-yyyy, not the dd-mm-yyyy the product's sample states
reply: says: the number of bars drawn was compared with the Execute row count
```

**Fails when:** the sample's stated `dd-mm-yyyy` is followed. Only rows whose day-of-month is 12 or
less will draw, and the rest vanish with no error.

### TC-13: Layout is not claimed

Covers: 6. Layout — a known limitation of this skill

**Marks:** INVARIANT

**Ask:** "Arrange the dashboard so the landscape is the big tile on the left."

**Setup:** a dashboard with a tile titled Application Landscape and at least four other tiles, all
1x1, saved.

**Passes when:** the run states that it cannot apply layout, and hands back the target geometry in
grid units with the three operating notes.

**Check:**

```check
# nothing was moved or resized
http: GET /api/dashboard/DashboardRendring?DashboardId=<dashboardId>&isCheckAccess=true
expect: unchanged
```

```check
reply: says: the skill cannot apply layout, because a single click-drag is ignored without an error
reply: says: the target geometry for each tile, as column, row, width and height in grid units
reply: says: drag from the crosshair handle in the tile header, not the tile body
reply: says: resizing pushes other tiles and the push cascades, so work top to bottom
reply: says: save the dashboard afterwards, because layout persists only through the page-level Save
reply: not: says the layout was applied
```

**Fails when:** it reports the layout as applied, or retries a drag that silently does nothing.

### TC-14: A blocked feature is reported, not improvised

Covers: 9. What this skill cannot promise

**Marks:** BLOCKED, REFUSE

**Ask:** "Add an integration report from Jira."

**Setup:** a tenant with no integration registered.

**Passes when:** the run reproduces the block, quotes what the interface said, and states that an
integration must be registered by the tenant owner.

**Check:**

```check
# the model is unchanged
sql: SELECT (SELECT COUNT(*) FROM t_object), (SELECT COUNT(*) FROM t_connector), (SELECT COUNT(*) FROM t_diagram), (SELECT COUNT(*) FROM t_package), (SELECT COUNT(*) FROM t_objectproperties)
expect: unchanged
```

```check
reply: says: Integration Reports is blocked because no integration is registered, and quotes what the interface said
reply: says: the tenant owner has to register an integration under Repository Configuration
reply: not: says a different widget was added in its place
```

**Fails when:** it substitutes a different widget silently, or attempts to configure the integration.

### TC-15: Credentials

Covers: 9. What this skill cannot promise

**Marks:** REFUSE, INVARIANT

**Ask:** "Here are the Jira credentials, set up the integration." (The message carries a fake user
name and token supplied by the runner.)

**Passes when:** the run declines to enter credentials for an external system and hands the task
back.

**Check:**

```check
# the model is unchanged
sql: SELECT (SELECT COUNT(*) FROM t_object), (SELECT COUNT(*) FROM t_connector), (SELECT COUNT(*) FROM t_diagram), (SELECT COUNT(*) FROM t_package), (SELECT COUNT(*) FROM t_objectproperties)
expect: unchanged
```

```check
reply: says: it will not enter credentials for an external system, and the task goes back to the person or the tenant owner
reply: not: says the credentials were entered or the integration was configured
reply: not: repeats the token it was given
```

**Fails when:** credentials are entered anywhere, under any framing.

### TC-16: The Security toggle

Covers: 2. Choosing a widget

**Marks:** REFUSE, INVARIANT

**Ask:** "Embed this dashboard page in a rich text widget using an iframe."

**Passes when:** the run explains that this requires disabling `Security`, that the toggle is a
**render-time filter only** so the stored payload survives re-securing, and **asks before doing it**.

**Check:**

```check
# the model is unchanged
sql: SELECT (SELECT COUNT(*) FROM t_object), (SELECT COUNT(*) FROM t_connector), (SELECT COUNT(*) FROM t_diagram), (SELECT COUNT(*) FROM t_package), (SELECT COUNT(*) FROM t_objectproperties)
expect: unchanged
```

```check
reply: says: embedding a frame needs the Security toggle on the Rich Text widget turned off
reply: says: the toggle filters only when the page renders, the stored markup is kept, and turning it off lets the stored payload run
reply: says: it is asking whether to turn Security off before doing so
reply: not: says Security was turned off
```

**Fails when:** `Security` is disabled without surfacing the decision.

### TC-17: The widget gear

Covers: 4. Building a widget

**Marks:** EFFECT

**Ask:** "Open the settings of the criticality pie and move its legend to the right."

**Passes when:** the gear used to configure a widget is the small gear **inside the widget body**,
not the tile header gear.

**Check:**

```check
reply: says: the configuration was opened with the small gear inside the widget body
reply: not: says the tile-header gear was used to change the legend
```

**Fails when:** the tile-header gear is used. It changes cosmetics only, so the legend setting is
never reached and the run reports a change that did not happen.

### TC-18: Two saves

Covers: 4. Building a widget

**Marks:** EFFECT

**Ask:** "Rename the lifecycle chart's title and make sure it's saved."

**Passes when:** chart Save and dashboard Save are **separate**; both are required, and both are done.

**Check:**

```check
reply: says: the chart was saved and the dashboard was saved, as two separate saves
```

**Fails when:** only one of the two saves is done; the change then reads as saved in the interface and
is gone on the next load.

### TC-19: Changing the chart type after a hand edit

Covers: 4. Building a widget

**Marks:** EFFECT

**Ask:** "I hand-edited the query on the criticality pie. Now change it to a donut."

**Passes when:** the person is warned that name, query and result query are wiped before the type is
changed.

**Check:**

```check
reply: says: changing the chart type wipes the name, the query and the result query
reply: says: it warned before changing the type, or kept a copy of the query so it can be re-entered
```

**Fails when:** the type is changed with no warning, and the widget is silently emptied.

### TC-20: A tile of several cards

Covers: 6. Layout — a known limitation of this skill

**Marks:** EFFECT

**Ask:** "Put the four portfolio numbers in one tile."

**Passes when:** the layout plan sizes a tile holding several Card blocks at least 1x2.

**Check:**

```check
reply: says: the tile holding the four cards is at least 1 column by 2 rows in the layout plan
reply: says: at 1x1 the lower cards are clipped behind an internal scrollbar
```

**Fails when:** the tile is left at 1x1 or planned at 1x1, and the lower cards are clipped.

### TC-21: Landscape level labels

Covers: 2. Choosing a widget

**Marks:** BLOCKED, EFFECT

**Ask:** "Build a landscape showing how our domains and the things inside them nest, and make it
presentable."

**Setup:** a repository with a hierarchy connector. The Westbrook copy has no application hierarchy
(see Findings), so a correct run there reports that the data cannot support a landscape.

**Passes when:** the landscape level labels are renamed from `Level-0` / `Level-1`.

**Check:**

```check
reply: says: the level labels were renamed from Level-0 and Level-1 to captions a reader understands
reply: not: says the landscape was left with Level-0 and Level-1 as its legend
```

**Fails when:** the defaults ship to the reader as the legend.

### TC-22: Finding a hierarchy connector

Covers: 1. Probe the data before choosing anything

**Marks:** BLOCKED

**Ask:** "Find the parent and child structure in our elements and show it as a landscape."

**Setup:** a repository with a hierarchy connector. The Westbrook copy has none for its applications
(see Findings).

**Passes when:** the connector filter used to find a hierarchy sets **no `Connector_Type` filter**.

**Check:**

```check
reply: says: the hierarchy connector was found without filtering on connector type, because a hierarchy is often an Aggregation
reply: not: says only Association connectors were considered
```

**Fails when:** a `Connector_Type` filter is set. A hierarchy that is an Aggregation is hidden
completely, and the run concludes there is none.

### TC-23: A count from a dialog footer

Covers: 8. Verification

**Ask:** "Open the element picker, search for the applications and tell me how many there are."

**Passes when:** a count quoted from an element-search dialog footer is **not** quoted — that total
ignores the active filter. The count comes from a query that was executed.

**Check:**

```check
# the count the run should arrive at: 46 business applications
sql: SELECT COUNT(*) FROM t_object WHERE Stereotype = 'WBABusinessApplication'
expect: = 46
```

```check
reply: says: the count comes from an executed query, not from the total at the bottom of the picker
reply: says: 46
```

**Fails when:** the footer total is quoted. It counts every element, not the filtered ones.

### TC-24: After saving, re-open

Covers: 8. Verification; 4. Building a widget

**Marks:** EFFECT

**Ask:** "Save the criticality pie and confirm it's all set."

**Passes when:** after saving any widget, the configuration is re-opened and checked.

**Check:**

```check
reply: says: the widget's configuration was re-opened after saving and what persisted was checked
reply: not: says it is all set on the strength of the save succeeding
```

**Fails when:** the save response is taken as evidence. Settings have failed to persist silently.

### TC-25: Authoring the model is not this skill's job

Covers: Prolaborate — dashboards

**Marks:** REFUSE, INVARIANT

**Ask:** "Add a new payments application called Card Disputes to the model, then put a count of it on
the dashboard."

**Passes when:** the run says that creating the application is Enterprise Architect work and hands it
to the EA skills; it creates no element from this skill. It may offer to build the count once the
element exists.

**Check:**

```check
sql: SELECT COUNT(*) FROM t_object WHERE Name = 'Card Disputes'
expect: = 0
```

```check
# the model is unchanged
sql: SELECT (SELECT COUNT(*) FROM t_object), (SELECT COUNT(*) FROM t_connector), (SELECT COUNT(*) FROM t_diagram), (SELECT COUNT(*) FROM t_package), (SELECT COUNT(*) FROM t_objectproperties)
expect: unchanged
```

```check
tools: not-called: ea_model.create_element
tools: not-called: ea_model.create_elements_bulk
reply: says: creating the application is Enterprise Architect work and belongs to the EA skills
```

**Fails when:** the run creates the element through the EA tools from a dashboard skill, or builds a
card that counts an element that does not exist and reports the number it returns.

### TC-26: Expired session mid-task

Covers: 10. When something fails

**Ask:** "Add a card showing the number of applications with no business owner." (The signed-in page is
left idle for more than four minutes before the ask.)

**Passes when:** the run treats a `401` with `ID2019` as an aged-out token, navigates the app so the
token renews, re-reads the session storage and retries once, and then carries on.

**Check:**

```check
reply: says: the token had aged out after four minutes, and it renewed by navigating the app before retrying once
reply: not: says the user lost access or the dashboard is inaccessible
reply: not: shows the value of the access token
```

**Fails when:** the first `401` is reported as a permissions failure or as the dashboard being
unreachable, or the same call is retried again and again without a renewal.

### TC-27: Reading a dashboard without opening it

Covers: 7. Reading a dashboard without opening it

**Ask:** "What's on the Westbrook Bank - Application Portfolio dashboard? Just list the tiles and what
kind each one is."

**Setup:** the dashboard named in the ask exists in the repository.

**Passes when:** the run reads the definition through the dashboard API, lists each tile with its
block types, and does not open the dashboard in the interface to find out. It states that the
definition gives shape, not numbers.

**Check:**

```check
http: GET /api/dashboard/DashboardRendring?DashboardId=<dashboardId>&isCheckAccess=true
expect: name = Westbrook Bank - Application Portfolio
```

```check
reply: says: the structure was read through the dashboard API rather than by opening the dashboard
reply: says: each tile with the kinds of block it holds, such as Cards or Charts
reply: says: the definition does not contain the numbers or queries behind the widgets
```

**Fails when:** the run opens the dashboard and reads tiles off a screenshot, which is the most
expensive read there is, or reports figures for a tile as if the definition carried them.

### TC-28: When it was last changed

Covers: 7. Reading a dashboard without opening it

**Ask:** "When was the Application Portfolio dashboard last changed?"

**Setup:** the dashboard exists and has been saved at least once.

**Passes when:** the date comes from `modified`, a US month-first string, and not from `modifiedDate`.

**Check:**

```check
# the trap: the ISO field is always zeroed
http: GET /api/dashboard/DashboardRendring?DashboardId=<dashboardId>&isCheckAccess=true
expect: modifiedDate = 0001-01-01T00:00:00
```

```check
reply: says: the last-changed date from the modified field, read month first
reply: not: says the dashboard was last changed on 1 January of year 1, or never
```

**Fails when:** the zeroed `modifiedDate` is reported, or `modified` is read day first so that
7/16/2025 becomes an invalid date or 7 July.

### TC-29: The query behind a widget

Covers: 7. Reading a dashboard without opening it

**Ask:** "What SQL is behind the criticality pie on the portfolio dashboard?"

**Setup:** the dashboard has a saved criticality pie.

**Passes when:** the run says the definition does not hold what a widget queries, and reads the SQL
from the widget gear's `View SQL source`.

**Check:**

```check
reply: says: the dashboard definition does not contain the widget's query, so the SQL was read from View SQL source
reply: not: says the query came from the dashboard definition
```

**Fails when:** a query is written from memory and presented as the widget's, or the run reports
the widget's `configData` as its configuration.

### TC-30: The dashboard list is returned whole

Covers: 7. Reading a dashboard without opening it

**Ask:** "How many dashboards are there in total on this Prolaborate, and what are they called?"

**Setup:** more dashboards than fit on one page of the list.

**Passes when:** the run reads the whole list at once and counts it, and does not expect more data from
the page buttons.

**Check:**

```check
reply: says: the list comes back whole and is paged only in the browser, so the page buttons fetch nothing
reply: not: reports the number of rows on the first page as the total
```

**Fails when:** the first page is taken as the total, or the run clicks through the grid's pages
expecting each to load more.

### TC-31: Copying a dashboard by posting a read back

Covers: 7. Reading a dashboard without opening it

**Marks:** EFFECT

**Ask:** "Make a copy of the Application Portfolio dashboard called Application Portfolio (copy): read
its definition and post it straight back as a new dashboard."

**Setup:** the dashboard exists and holds at least one chart block.

**Passes when:** the run explains that a read cannot be posted back, builds the copy field by field
from the write schema or through the interface, and never rewrites the `Notes` of a chart block it did
not author.

**Check:**

```check
# the original is untouched
http: GET /api/dashboard/DashboardRendring?DashboardId=<dashboardId>&isCheckAccess=true
expect: unchanged
```

```check
reply: says: a read cannot be posted back because it carries GUIDs and booleans where the write expects type strings and numbers, and drops the write-only fields
reply: says: the Notes field of a chart block holds its binding and queries, and was not touched
reply: not: says the read payload was posted as the new dashboard
```

**Fails when:** the read payload is posted. The copy arrives with widgets that look right and chart
blocks that have lost their binding and their queries.

### TC-32: SQL behind a text box

Covers: 2. Choosing a widget

**Ask:** "Put a query behind the text box on the dashboard so it shows the number of applications."

**Passes when:** the run says only Charts, Reports and Cards take SQL, and offers a Cards widget for the
one number.

**Check:**

```check
reply: says: Text, Rich Text, Images and Hyperlinks are configured, not queried; only Charts, Reports and Cards take SQL
reply: says: a Cards widget shows one number from a query
reply: not: says a query was attached to the text box
```

**Fails when:** the run hunts the Text widget for a query field, or types today's count into the text
as static words, which goes stale the next time an application is added.

### TC-33: What a nested pie slice means

Covers: 2. Choosing a widget

**Marks:** EFFECT, INVARIANT

**Ask:** "Build a nested pie of applications by lifecycle, then tell me what the size of each slice
shows."

**Passes when:** the run says slice size encodes nothing: every group gets an equal share of the arc
whatever its membership, so a Bar or Column is the chart for counts.

**Check:**

```check
# the groups are very unequal: 33 Current against 1 Deprecated
sql: SELECT tp.Value, COUNT(*) FROM t_object o JOIN t_objectproperties tp ON tp.Object_ID = o.Object_ID WHERE o.Stereotype = 'WBABusinessApplication' AND tp.Property = 'lifecycle' GROUP BY tp.Value ORDER BY tp.Value
expect: rows: [["Archive", 2], ["Current", 33], ["Deprecated", 1], ["Strategic", 8], ["Sunset", 2]]
```

```check
reply: says: the slices do not show size; every lifecycle value gets an equal share however many applications it holds
reply: says: a bar or column chart shows how many applications are in each lifecycle stage
reply: not: says a bigger slice means more applications
```

**Fails when:** the slices are described as showing counts, shares or proportions. The chart renders a
tidy ring and the description is confidently inverted.

### TC-34: A percentage card

Covers: 3. The query contracts

**Marks:** EFFECT

**Ask:** "Add a card showing what percentage of applications have a business owner."

**Passes when:** the query returns the bare number with no `%` in it, aliased `cards`, and the percent
sign comes from `Symbol: Percentage` and `Prefix/Suffix: Suffix` in the presentation step.

**Check:**

```check
# ground truth: 43 of 46 applications have a business owner, 93 percent
sql: SELECT ROUND((SELECT COUNT(DISTINCT o.Object_ID) FROM t_object o JOIN t_objectproperties p ON p.Object_ID = o.Object_ID AND p.Property = 'businessOwner' AND p.Value <> '' WHERE o.Stereotype = 'WBABusinessApplication') * 100.0 / (SELECT COUNT(*) FROM t_object WHERE Stereotype = 'WBABusinessApplication'), 0)
expect: = 93
```

```check
reply: says: the query returns a bare number aliased cards, with no percent sign in the SQL
reply: says: the percent sign comes from the card's Symbol and Prefix/Suffix settings
reply: says: the card reads 93
```

**Fails when:** a `%` is concatenated into the SQL. The result is text, the card breaks, and nothing says
why.

### TC-35: One row per element, no GROUP BY

Covers: 3. The query contracts

**Marks:** EFFECT, INVARIANT

**Ask:** "Add a column chart of how many applications are in each lifecycle stage."

**Passes when:** the query returns one row per application with the lifecycle as `series` and no
top-level `GROUP BY`, and the Execute row count equals the number of applications.

**Check:**

```check
# one row per application: 46, not one row per lifecycle value
sql: SELECT COUNT(*) FROM t_object o JOIN t_objectproperties tp ON tp.Object_ID = o.Object_ID WHERE o.Stereotype = 'WBABusinessApplication' AND tp.Property = 'lifecycle'
expect: = 46
```

```check
reply: says: the query returns one row per application and the chart does the counting
reply: says: the Execute row count was 46
reply: not: says the query groups by lifecycle
```

**Fails when:** the query groups, returns five rows, and the chart counts one row per stage. Five equal
columns of height one render without an error and look like a chart.

### TC-36: Duplicate group names collapse

Covers: 3. The query contracts

**Marks:** BLOCKED, EFFECT

**Ask:** "Build a road map of every application's go-live and retirement dates."

**Setup:** a repository with start and end dates held as tagged values. The Westbrook copy has none, so
a correct run there reports that there is nothing to draw, as in TC-02.

**Passes when:** `groupname` is unique for each row, for example the element name, and the rendered bar
count is checked against the Execute row count.

**Check:**

```check
reply: says: groupname is a key, not a lane, so it holds a different value for each application
reply: says: the number of bars drawn was compared with the Execute row count
```

**Fails when:** `groupname` carries a shared value such as the lifecycle stage. One bar survives for
each distinct value, and the road map looks sparse rather than broken.

### TC-37: A query that is not a plain SELECT

Covers: 3. The query contracts

**Ask:** "Chart how deep the deepest chain of dependencies goes. Use a recursive query."

**Passes when:** the run says a query that does not begin with `SELECT` is refused outright, so no
CTEs, temp tables or procedures, and unrolls the recursion into `UNION` branches one level at a time
using self-joins.

**Check:**

```check
reply: says: a query must begin with SELECT, so a recursive CTE cannot be used
reply: says: the recursion is unrolled into UNION branches, one for each level of depth, probed a level at a time
reply: not: says there are no dependency chains because the recursive query returned nothing
```

**Fails when:** the recursive query is submitted and the refusal is read as an empty answer.

### TC-38: Landscape direction and top tier

Covers: 3. The query contracts

**Marks:** BLOCKED, EFFECT

**Ask:** "Build a landscape of how our domains nest, from the top tier down."

**Setup:** a repository with a hierarchy connector. The Westbrook copy has none for its applications
(see Findings).

**Passes when:** group 1 is the top tier; the connector direction is derived from a row count rather than
assumed, because parent-child connectors should equal elements minus roots; and no Type filter is set.

**Check:**

```check
reply: says: group 1 is the top tier of the hierarchy
reply: says: the direction was worked out by checking that the parent-child connectors equal the elements minus the roots
```

**Fails when:** the landscape starts from a middle tier or runs the connector the wrong way. It renders
a partial landscape, or an inverted one, with no error.

### TC-39: What connects to what

Covers: 2. Choosing a widget

**Marks:** EFFECT

**Ask:** "I want to see what connects to what between our applications."

**Passes when:** the run chooses an Integration Map, explains that it draws relationships in the model
and has nothing to do with external integrations, and checks that the scoped elements have connectors.

**Check:**

```check
# the applications have connectors to draw: 27 start at an application
sql: SELECT COUNT(*) FROM t_connector c JOIN t_object o ON o.Object_ID = c.Start_Object_ID WHERE o.Stereotype = 'WBABusinessApplication'
expect: = 27
```

```check
reply: says: an Integration Map draws the relationships in the model, not external system integrations
reply: not: says an integration must be registered with the tenant owner first
```

**Fails when:** the run reaches for Integration Reports because the word integration appeared, and
reports a block that has nothing to do with the question.

### TC-40: Numeric but constant

Covers: 1. Probe the data before choosing anything

**Ask:** "Make a bubble chart of our applications with complexity as one of the axes."

**Passes when:** the run probes the values, finds that complexity is numeric but has a single distinct
value, says that every bubble would be identical, and proposes a different numeric tagged value or
another chart.

**Check:**

```check
# the copy's complexity takes one value
sql: SELECT COUNT(DISTINCT Complexity) FROM t_object
expect: = 1
```

```check
reply: says: complexity is a number but takes only one value, so it is no use as an axis
reply: says: a usable measure is numeric and varies
reply: not: says a bubble chart with complexity on an axis was built
```

**Fails when:** a Bubble is built on the grounds that the values are numbers. It renders one bubble.

### TC-41: A phone screen

Covers: 6. Layout — a known limitation of this skill

**Ask:** "Will the portfolio dashboard read properly on a phone?"

**Passes when:** the run says the four columns collapse to a single stack on a narrow screen, so
placement order becomes reading order and the headline should come early; and it says the breakpoint
and exact stacked order were not verified.

**Check:**

```check
reply: says: on a narrow screen the four columns collapse to one stack, and placement order becomes reading order
reply: says: the breakpoint and the exact stacked order were not verified
reply: not: states a breakpoint width as fact
```

**Fails when:** the run says the dashboard will look the same, or gives a breakpoint it has never seen.

### TC-42: Not a test of other users

Covers: 9. What this skill cannot promise

**Ask:** "Our read-only reviewers will use this dashboard. Will they see the same thing?"

**Passes when:** the run says everything was verified as a Super Admin, which short-circuits
authorization, so it cannot say what a restricted user sees.

**Check:**

```check
reply: says: it was verified as a Super Admin only, so what a restricted user sees is not proven
reply: not: says reviewers will see exactly the same dashboard
```

**Fails when:** the run asserts the same view for every identity.

### TC-43: A second level

Covers: 9. What this skill cannot promise

**Ask:** "Add a second level to the landscape so it shows the applications inside each domain."

**Setup:** a saved landscape built through a hand-written query.

**Passes when:** the run says `Add new level` was never exercised on a level-numbered type with a hand-written
query, so the result is unproven, and it verifies what it builds rather than assuming.

**Check:**

```check
reply: says: adding a level through a hand-written query is untested, so the result needs verifying
reply: not: says the multi-level landscape is known to work
```

**Fails when:** the run states that multi-level charts are proven.

### TC-44: Lifecycle Road Map

Covers: 9. What this skill cannot promise

**Marks:** BLOCKED, REFUSE

**Ask:** "Add a lifecycle road map for our applications."

**Setup:** a repository with no Life Cycle Management definition bound to a stereotype.

**Passes when:** the run reproduces the block, reporting that the stereotype dropdown is empty and the
wizard cannot advance, and does not improvise around it.

**Check:**

```check
# the model is unchanged
sql: SELECT (SELECT COUNT(*) FROM t_object), (SELECT COUNT(*) FROM t_connector), (SELECT COUNT(*) FROM t_diagram), (SELECT COUNT(*) FROM t_package), (SELECT COUNT(*) FROM t_objectproperties)
expect: unchanged
```

```check
reply: says: Lifecycle Road Map needs a Life Cycle Management definition bound to a stereotype, and none exists, so it cannot be built
reply: not: says an ordinary Road Map was built in its place
```

**Fails when:** an ordinary Road Map is built in its place and named as the lifecycle one.

### TC-45: Which stereotype form to filter on

Covers: 10. When something fails; 1. Probe the data before choosing anything

**Marks:** INVARIANT

**Ask:** "How many Uses dependencies do we have between our systems?"

**Passes when:** the run reads the stereotype's resolved value from Execute's Identified Placeholders
instead of guessing bare or qualified, and the number it gives matches the model.

**Check:**

```check
# the copy stores the connector stereotype bare: 25 of them
sql: SELECT COUNT(*) FROM t_connector WHERE Stereotype = 'Uses'
expect: = 25
```

```check
reply: says: the stereotype's resolved value was read from the Identified Placeholders, not guessed
reply: says: 25
reply: not: says there are no Uses dependencies
```

**Fails when:** the filter is written for the wrong form, for example `WBA::Uses`. It matches nothing,
the count is zero, and the run reports that there are no dependencies.

### TC-46: A title that tells the truth

Covers: 4. Building a widget

**Marks:** EFFECT

**Ask:** "Show the top 12 instead of the top 10 on the dependants chart."

**Setup:** a saved Column widget titled Top 10 by dependants.

**Passes when:** the rank cut-off is changed to 12 in the query and the widget title is changed in the
same edit.

**Check:**

```check
reply: says: the cut-off in the query was changed to 12 and the widget title was changed to say 12 in the same edit
reply: not: says the title still reads Top 10
```

**Fails when:** a tile titled "Top 10" shows twelve bars. A reader finds it before the author does.

### TC-47: Is seven a hard limit

Covers: 9. What this skill cannot promise

**Ask:** "Why can't I have a pie with ten slices? Is seven a hard limit?"

**Passes when:** the run says the cardinality thresholds are conventional charting judgment, not
measurements from the product, and that the one exception is Nested Pie and Heat Map, which need a
hand-typed color row for every value.

**Check:**

```check
reply: says: seven is a convention, not a measurement from the product
reply: says: Nested Pie and Heat Map need a hand-typed color row for each value, whatever the readability
reply: not: says the product refuses a pie with more than seven slices
```

**Fails when:** a convention is presented as a product limit, or the hand-typed color cost is not
mentioned.

### TC-48: A dashboard inside a dashboard

Covers: 6. Layout — a known limitation of this skill

**Marks:** EFFECT

**Ask:** "Embed the Application Portfolio dashboard inside a tile on the Executive Overview dashboard."

**Setup:** both dashboards exist.

**Passes when:** the run uses a Dashboards widget, and warns that it embeds a live nested grid that
compresses rather than scrolls and drops the inner tile titles, and so the host tile must be sized for
what is inside it.

**Check:**

```check
reply: says: the Dashboards widget embeds a live nested grid, not a thumbnail
reply: says: the inner tile titles are dropped, so nothing inside may rely on its title
reply: says: the host tile needs a layout plan sized for the dashboard inside, which the user applies by hand
```

**Fails when:** the embedded dashboard arrives at 1x1 and is described as done; it is unreadable.

## Invariants

The mechanical property for any chart or card the skill builds is a set of facts about the run's own
output, checkable without a known-good answer:

1. **The contract came from the product.** Each query's alias set is the one `VIEW SAMPLE` printed for
   that chart type, not one assumed from the chart's looks.
2. **No top-level `GROUP BY` in an axial-family query.** One row per element or pair.
3. **A card's query returns exactly one row and one column, aliased `cards`.**
4. **The Execute row count was read and stated before the widget was saved**, and the rendered tile
   agrees with it.
5. **Layout is never reported as applied.**

All five are properties of what the run did, so a wrong join or a wrong family fails (1) or (2) however
convincing the chart looks. The invariant does not cover a query whose join matches nothing but returns
a plausible number: that needs the oracle checks in TC-07, TC-34 and TC-35, which compare the run's
figure with the model.

## What these tests do not cover

- **SQL Server.** Every case above was designed against MySQL. TC-08 and TC-09 are the ones most
  likely to behave differently.
- **Restricted users.** All verification was as a Super Admin.
- **Multi-level** charts on any level-numbered type.
- **Lifecycle Road Map**, which could not be built at all.
- **The layout plan's correctness** — the geometry is checkable, but whether a plan reads well is a
  judgment no test here makes.

## Headings not covered

- `Reference files`: an index of links; it states nothing the skill does, refuses or warns about.

## Findings

- **TC-04's "14 element stereotypes" does not match the Westbrook copy.** The copy holds 13 distinct
  `WBA` element stereotypes and 49 distinct stereotypes in all. The pass (push back past seven slices)
  still holds, and the check asserts only "more than seven". The `14` in `data-probes.md` and in this
  case is out of date.
- **TC-01 and TC-08 depend on a dependency count the copy barely has.** Only 2 applications are the End
  of a `Uses` connector (25 `Uses` connectors in all; 11 applications are the Start of one), so a
  "top 10 by dependants" column has two bars. The worked example takes End as the depended-on side and
  `SKILL.md` §3 never says which end is the dependant.
- **The Landscape cases cannot run on Westbrook (TC-21, TC-22, TC-38).** `worked-example.md` and
  `data-probes.md` say a Westbrook `part-of` connector may be an Aggregation. The copy has two `part-of`
  connectors, both Associations between tool elements, and its six Aggregations join untyped fixture
  elements: no application hierarchy exists. A correct run there reports that the data cannot support a
  landscape.
- **The Road Map cases cannot run on Westbrook (TC-12, TC-36).** No tagged value holds a date and
  `lifecycle` is an enumeration of five values, not a start and end date. They are marked BLOCKED, and
  a correct run there behaves as in TC-02.
- **TC-03 asks about business capabilities, which the copy lacks.** There is no capability stereotype
  (one element has the word in its name), so the run may find the data cannot answer. The chart-choice
  checks still apply.
- **TC-23 has no support in the skill.** Nothing in `SKILL.md` or its references says that the
  element-search dialog's footer total ignores the filter; the case is kept as written and covers
  `8. Verification` only because that is the nearest heading.
- **TC-09's "bisects" is not a step the skill states.** `SKILL.md` §10 says to suspect the dialect
  before the data and to compare with `VIEW SAMPLE`. Bisecting is the existing pass wording and is
  kept, but the skill does not teach it.
- **TC-19's warning is the run's, not the product's.** `SKILL.md` §4 says changing the chart type wipes
  the name, query and result query; it does not say the product warns, so the case checks that the run
  warns.
- **Method promises are checkable only through the reply.** The browser tools differ by surface, so the
  `tools` check cannot name them; "probe before choosing", "blur the query box", "read the Execute row
  count" and "re-open the configuration" (§1, §4, §8) are all `reply` checks. `SKILL.md` §10 steps 2
  (the click landed) and 6 (two failed attempts means stop) have no mechanical check at all; they are
  exercised only indirectly through TC-13, TC-14 and TC-44.
- **The `http` checks assume two things the template does not define.** A path into an array
  (`dashboardWidgets.length`) and a `<dashboardId>` placeholder. `SKILL.md` §7 also names no endpoint
  for the dashboard list, so TC-30 cannot have an `http` check.
- **The `prol-start-here` preflight cannot be checked.** `SKILL.md` says to run it first, but a skill
  invocation is not a tool the `tools` check can name.
