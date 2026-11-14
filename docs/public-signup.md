# Public sign-up and guest browsing

A Fuobe studio with a password can open itself a little to the public: signed-out visitors (guests)
browse it read-only, and anyone can make a free account. It is off by default, so a self-hosted
studio behaves as before: every page and API call needs the install password or an API token.

## Turning it on

Public sign-up works only on a studio that has a password (`FUOBE_PASSWORD` or **Settings →
Security**). Then it is on when one of these is true:

- `FUOBE_PUBLIC_SIGNUP=1` is set on the server. `FUOBE_PUBLIC_SIGNUP=0` keeps it off, whatever
  Settings says. While the variable is set, the Settings switch can't change it.
- The owner turns on **Settings → Security → Public sign-up**.
- The request is for `fuobe.com` or `www.fuobe.com` (the public demo), the server lists that name in
  `FUOBE_ALLOWED_ORIGINS`, and `FUOBE_PUBLIC_SIGNUP` is not `0`. The `Host` header comes from the
  client, so a self-hosted studio that someone reaches by its IP address can't be opened with
  `Host: fuobe.com`.

Turning it off signs out every account at once, and guests are sent to sign in again.

## Guests

A guest can open every page: galleries, presets, the studios, Layers, Cinema, Image to 3D and
Settings, read-only. The pages get the catalog and status reads they need (`/api/status`,
`/api/models`, `/api/search-index`, `/api/comfyui`, `/api/settings/models`, curated moodboards,
built-in skills), and the bar's menus read `/nav-menus/apps`, `/nav-menus/motions` and
`/nav-menus/canvas`: static files made at build time that hold what a visitor may see only (no model
names, no template without a real cover). The owner's library stays private: the lists come back empty, and other reads of
it (files, uploads, projects, settings values, tokens) answer 401 "Sign up to see your library".

Every change a guest sends (generate, upload, save a setting, create a project…) answers 401. The
studio shows a "Create a free account to run this" card with **Sign up** and **Log in**. Where
signing up wouldn't help, a guest gets an account's answer instead: 403 `assist-owner` for Assist,
and 403 `own-gpu-tool` for a tool an account's own GPU or key doesn't run (Katana,
Marketing…). The pages of those tools say so up front and turn off their upload and Generate.
What is drawn in the browser itself is open to try: Click to Ad's animated end card and Marketing
Studio's code-drawn templates (Kinetic Motion) take a guest's words and play live (a code-drawn
template shows no "isn't available" note, as nothing is generated); their Save opens the sign-up card before anything renders.
The Kinetic page (`/kinetic`) is open the same way: a guest plays and edits every scene (Easy and Pro, presets,
timing, undo), and Save, Save frame, Save contact sheet, Save version, "Pick a clip" and an upload open the sign-up
card before anything renders or uploads. A guest's versions list is empty and `/kinetic?from=<id>` opens the scene
picker. Price
checks (the estimate routes, and `?preview=1` on the run routes that support it) stay open, so the
studios can show prices. A guest may send 120 price checks a minute (per visitor behind a trusted
reverse proxy; see below), and so may each account. A price check reads only the header of a file
it names, and only of the asker's own files (a guest owns none) or of Fuobe's published example files. Nor does a price check reveal the
owner's library: the turnaround video's price check (`/api/turnaround/estimate`, or
`/api/turnaround?preview=1`) answers 404 "Character not found" for any character a visitor names,
whether it exists or not. A price check never calls a GPU either: Split soundtrack's price check
takes an account's GPU type from the status strip's last check and asks the GPU nothing.

## Accounts

- Sign up at `/login?signup=1` (`POST /api/auth/signup` with `{ "email", "password" }`). The
  password needs at least 8 characters. There is no email verification.
- Log in at `/login` (`POST /api/auth/login` with `{ "email", "password" }`). The install password
  still works as before: `POST /api/auth/login` with `{ "password" }`, or the owner's sign-in at
  `/login?owner=1`. The login page links to it only in development, so a public site doesn't
  advertise it.
- Or **Continue with Google** or **Continue with GitHub**, when the install has set them up
  ([Google and GitHub](#google-and-github)).
- Accounts are stored in the database (`fuobe.db` in the data folder, table `auth_accounts`): the
  email in lower case (one account per email), a salted scrypt hash of the password (the same scheme
  as the install password), and the creation time. An install from before this kept them in
  `auth.json`, which moves into the database on the first start ([Sign-in data](SELF-HOSTING.md#sign-in-data)).
- Sign-up and log-in attempts are rate limited per visitor (set `FUOBE_TRUST_PROXY=1` behind a
  reverse proxy, so that each visitor gets their own limit; an IPv6 address counts by its /64).
  A visitor gets 30 account log-ins a minute, right or wrong, and 10 a minute for one email. After
  5 wrong passwords for one email, that visitor is locked out of it for 15 minutes. After 10 wrong
  passwords for one email from any number of addresses, the email is locked for 15 minutes, but
  only for the addresses that got it wrong twice or more. The person whose account it is still
  gets in from anywhere else, so nobody can lock a chosen account out. Account log-ins and the
  install password have separate limits, so guessing at one never slows down the other.

An account is signed in, but it sees the owner's studio as a guest does:

- **The owner's library stays the owner's.** An account opens every page and the catalog, but the
  owner's results, files, uploads, folders, shares, projects (Layers, Cinema, Canvas, storyboards,
  elements…) and Assist threads are hidden: the lists come back empty, and other reads answer 403.
  Every change to them (create, rename, move, share, delete) answers 403 with `code: "library"`.
  Accounts have their own uploads and runs (below), their own Cinema Studio projects, and their own Faceless
  channels, explainers and Content Factory series.
  A Canvas Kinetic node renders in the owner's browser; keeping its run on the board
  (`PUT /api/canvases/<id>/runs/<node>`) is a canvas change like any other (403 `library` for an account, 401
  for a guest), and it takes only the owner's own finished Kinetic Motion results.
  **Canvas is open to build in.** Each ready board has its page (`/canvas/start/<id>`: what goes in, the
  steps and what comes out), and **Use this board** opens it in the Canvas editor (`/canvas/try/<id>`,
  or `/canvas/try/blank` for a blank one) with every node and link in place, its inputs holding
  Fuobe's published example files (by their public path, never a copy in anyone's storage) and its
  last step showing the board's own published film. A guest builds and changes boards there; the
  first change keeps the board in that browser only (`/canvas/draft/<id>`, localStorage, up to 20,
  nothing sent to the server), and **Save** offers a free account. An account saves its boards to its
  account (`/canvas/saved/<id>`; `GET`/`POST /api/account/canvases`, `GET`/`PATCH`/`DELETE
  /api/account/canvases/<id>`): its own boards only (another account's reads as 404, a guest gets
  401), up to 50 boards of 1 MB each and 120 saves a minute, deleted with the account. Its inputs
  take its own uploads or Fuobe's published example files, nothing else. The owner's canvases
  (`/api/canvases`) stay the owner's (403 `library` for an account). **Run** on a visitor's board
  never runs: a canvas plans with the studio's own AI helpers, so it says what running needs and
  links the Video effect that makes the same film in one step (or the studios); its steps name no
  price or run state, and a ready board's last step says Example. On a phone the
  board shows read-only with its steps editable in Nodes. Assist, Cinema Studio,
  Storyboard, Elements, Faceless Studio, Content Factory, Explainer, Ads Studio, Click to Ad and
  Marketing Studio show their ready-made starters the same way (`<studio>/start/<id>`); making one
  (`POST /api/starters/<id>`) is the owner's, and an account gets 403 `library`, except Cinema Studio's
  ready films and Faceless Studio's ready channels, which an account makes as its own project (a guest gets the sign-up
  card). Content Factory's and the Explainer's ready ones fill the composer for anyone. A starter without its
  cover yet is the owner's only: its card, its words and its page (404 for anyone else). Storyboard's
  ready stories with a cover also fill its composer for anyone (`/storyboard?starter=<id>`), and the
  Library's "Make your first" row links to pages everyone can open.
- **Settings, keys and tokens are the owner's.** Changing settings or model switches, the password,
  API tokens, Public sign-up, LoRA downloads, Assist connectors and the MCP endpoint answer 403 for
  an account.
- **Accounts never run on the owner's keys or GPU.** An account runs on its own ComfyUI (see
  [Your GPU](#your-gpu)) or its own fal.ai or Replicate key (see [Your keys](#your-keys)). With
  neither, anything that would reach a model (a generation, an AI helper, a retry) answers 403
  with `code: "connect-gpu"`, and the studio shows a "Connect your GPU to run this" card.
- **Its own runs are its own.** The runs an account starts on its GPU appear in its own lists
  (`GET /api/generations`), and it can open, cancel and delete them and download their files. They
  stay out of the owner's Library and live feed, and no other account can open them. The studio's
  owner can see them, open their files and delete them ([Managing accounts](#managing-accounts));
  the sign-up form says so. An account's delete is for good (it has no Trash): a result's ⋯ menu and the
  Library's selection bar say **Delete for good…** and ask first, and its space comes
  back at once. The live-updates stream isn't sent to accounts: their studios poll instead.
- **It downloads its own runs as one zip.** The Library's **Download**, a result's **Download all** and Shorts'
  **Download parts** go to `GET /api/generations/zip`, which zips the account's own runs only: another account's run or
  the owner's is left out, exactly as one that doesn't exist (none of its own: 404), so the answer never says whether
  it is there. A file held for its check is left out too. One zip takes up to 200 runs and 1 GB (413 past either), and
  an account makes one zip at a time (429 while one is going; a download that stops, or stalls for 2 minutes, frees
  it). The zip is streamed from the files, so it uses no disk or memory. The Library asks first (`?check=1`), so a
  refusal shows as a message. A guest gets the sign-up card.
- **Its own uploads are its own.** Only the account that uploaded a file can use it in a run, and
  no other account can open it. See [Uploads](#uploads).
- **Results made in the browser are its own runs too.** A motion clip rendered in
  the page (an animated end card, a text template, anything made on the Kinetic page) is saved with an upload and
  `POST /api/generations/local` (`op: "motion"`, model `local-motion`). No model makes it, so any
  account may save one, with or without its own GPU or key (the upload is sent with
  `x-fuobe-kinetic: 1`; see [Uploads](#uploads)). It counts as the account's own runs and files: the clip and every file it
  names (its pictures, and the recipe's logo, product, pictures and clip) must be the account's own (403
  otherwise). Frames, contact sheets and versions are Kinetic results too (`feature` `kinetic-frame`,
  `kinetic-sheet` or `kinetic-version`, a PNG picture of the size its recipe makes: the export size for a frame or a
  sheet, the rest frame 540 px on its long side for a version; 400 otherwise); a clip under the words must be the account's own stored video,
  and a video input is taken only when it is the recipe's own clip (`layers.video.src`; 400 otherwise). The stored
  file must be the MP4, WebM or (for those three) PNG it claims to be (400), and it shares the account's hourly run budget (60 an hour with its other runs,
  429). The words drawn on the clip (the recipe's fields and brand name) and its title go through the
  studio's checks when they are on, whatever the page sends as the prompt, and are what the run keeps
  (a refusal answers 422; a result the checks want to see waits for them). It shows in the account's
  own runs, never the owner's Library. Nothing
  is downloaded straight from the page: the clip is downloaded from the saved result. A guest's
  call answers 401 with the sign-up card.
  A **colour grade** (`op: "grade"`, model `local-color-grade`) and a **Relight blend** (`op: "relight"`,
  model `local-relight`) are kept the same way: the same upload, its own stored PNG picture or MP4 or WebM clip
  (400 otherwise), made from its own files only (a file picked on the page stays in the browser, so the grade names
  no input), within the same run budget and through the same checks (its description and title). Colour grading's
  **Save to your runs** shows for an account; a guest's Save opens the sign-up card.
  Split soundtrack's **Export mix** (`POST /api/audio-tools/export`, the WAV in parts) is kept as one of its runs
  too (`feature` `audio-split-mix`, model `local-mix`): its WAV goes into its own files, no bigger than the room
  they have left (413), one export at a time (a new one drops the unfinished one), and a part with another viewer's
  export id answers 404. The last part answers 201 with the run, within the same run budget (429) and through the
  same checks (422).

## Google and GitHub

An install can let visitors sign up and log in with Google or GitHub as well as with an email and a
password. It is off unless the install sets a provider's client id and secret, and it works only
while public sign-up is on. The owner's sign-in (the install password) doesn't change.

| Provider | Variables | Callback URL to register |
|---|---|---|
| Google (an OAuth client of type "Web application") | `FUOBE_OAUTH_GOOGLE_ID`, `FUOBE_OAUTH_GOOGLE_SECRET` | `<your site>/api/auth/oauth/google/callback` |
| GitHub (an OAuth app) | `FUOBE_OAUTH_GITHUB_ID`, `FUOBE_OAUTH_GITHUB_SECRET` | `<your site>/api/auth/oauth/github/callback` |

`<your site>` is the address visitors open, with its scheme (`https://studio.example.com`). Behind a
reverse proxy, the proxy must send `X-Forwarded-Host` and `X-Forwarded-Proto` (or the original `Host`),
so the callback address matches the one registered.

- **Switching one off.** **Settings → Security → Sign in with Google** and **Sign in with GitHub**
  (settings `oauthGoogle` and `oauthGithub`, `on` or `off`) show for each provider whose id and
  secret are set. They are on by default; off hides the button and closes its routes at once, with no
  restart.
- **The buttons.** With a provider set up, the sign-in and sign-up forms show **Continue with Google**
  and **Continue with GitHub** above the email form. `GET /api/auth/me` lists the providers that are
  on (`oauth: ["google", "github"]`) while sign-up is open.
- **The flow.** `GET /api/auth/oauth/<provider>?next=<path>` sends the browser to the provider (the
  authorization-code flow, with PKCE). A random `state` is kept for 10 minutes in an HttpOnly cookie
  signed with the install's secret, and the callback (`GET /api/auth/oauth/<provider>/callback`)
  takes the code only with that browser's state. `next` must be a path on this site: anything else
  goes to the home page. Both routes answer 404 while the provider isn't set up or sign-up is off.
- **A verified email only.** Google's email counts only when Google says it is verified. GitHub's
  counts only when it is the account's primary email and verified. Without one, the login page says
  so, and no account is made.
- **Which account.** A provider's user signs in to the account linked to it before (by the provider's
  own user id), else to the account with the same email, which is then linked. Otherwise an account
  is made as sign-up makes one, within the same sign-up limits for the visitor, and a new account goes
  to the welcome page first. A switched-off account can't log in this way either. Only the provider's
  user id is kept (table `auth_oauth_links`), never a code or a token. The account's email then counts
  as confirmed, and an optional billing service hears `emailVerified: true` and `signIn: "google"` or
  `"github"` ([billing-hook.md](billing-hook.md)).
- **An unconfirmed email is taken over.** Email sign-up doesn't confirm the address, so someone else
  may have set an account's password. When a provider's user first reaches an account by its email
  and that email was never confirmed, the account's password stops working and its other sign-ins
  end; it then reads as an account made with the provider (below). An account whose email was
  confirmed keeps its password.
- **No password at first.** An account made with a provider has no password: no password logs in to
  it. **Settings → Account → Set a password** gives it one (`PATCH /api/auth/me` with
  `{ "next" }`), and deleting it asks for no password. Both need a sign-in with the provider in the
  last 10 minutes; past that they answer 403 with `code: "sign-in-again"`, and the page offers
  **Continue with Google** (or GitHub) again.
- Codes, tokens and the client secret are never logged. A failed provider call logs its status only.

## Managing accounts

The owner sees everyone who signed up in **Settings → Accounts**, the last section of Settings (the
**Accounts** chip at the top of Settings and the link under Public sign-up lead there): email,
whether its own GPU is connected, its runs (all time, in the last 7 days, running now, failed in the
last 7 days), when it last ran, and the space its files take against its limit (5 GB). On wide screens the list also shows when the account was created and its last
log-in (the CSV always has them). Running now counts as the run limit does: a batch or a chain
going is one run. A line above the list gives the runs of every account in the last 24 hours and 7
days, the runs going now, and the space all accounts' files take against their share of the disk.
The owner can switch an account off (it is signed out at once and can't log in) or delete it, and
export the list as CSV. If an `auth.json` turns up in the data folder after the sign-in data moved
into the database, the section also shows a notice. Visitors never see it. The file is not used: it
is set aside under a new name, and sign-in goes on from the database. The notice gives the file's
name and how many accounts and API tokens it lists
([Sign-in data](SELF-HOSTING.md#sign-in-data)).

**Accounts' runs** (`/settings/runs`, from the list) shows what accounts made, newest first: one
account's or every account's, each labelled with its email, filtered by account, status (finished,
running, failed) and kind. The filters are in the address (`?account=<id>&status=failed&kind=video`),
so a reload or a shared link keeps them. Each run shows its result (a clip plays on hover, a tap, or
Enter; the count on a run with several files steps through them, and its menu opens each one), the
app, preset or studio and the model, the prompt, its status with the error of a failed run, and when
it ran. The owner can delete a run with its files, which gives the account its space back at once, or
switch the account off from there. The owner's own runs are never listed there, and accounts' runs
never appear in the owner's Library, its counts or the live feed.

**Run details** (`/settings/runs/<run id>`: a run's name or **Run details** in its menu) shows everything about
one account's run. It shows what the account saw: its studio tile and its Library card, made by the same components
the account's pages use, with the same words, details line and buttons (nothing on it can be pressed). It shows what
went wrong: the stored error, the cause, the buttons the account was given, the files missing on its GPU, and the
note kept when it failed (stage, code, the GPU's or provider's own words). It shows where the run went: its own GPU
(a RunPod pod, a tunnel, a LAN or web address, its own computer), its own key, or this site's GPUs, and the graph.
It shows the model, the app, preset or studio, the prompt and negative prompt, and each setting beside the default
the composer would have started with (marked Default, Changed or Unknown default; a default that isn't known is
never guessed). It shows the input files (an upload that was cleared after 14 days says Removed), the other runs of
its batch, and the account's runs from 2 hours before to 6 hours after it. A Retry is the same request sent again,
so it shows as **Same request again**; a change of model shows as the same words and files on another model. A
collapsed section shows what was sent to the GPU or provider. Links show by their kind only, and keys, tokens,
cookies and passwords are left out.

It also shows how long the run waited and ran: a timeline from the press to the end, with each worker that took
its job, gave it back or finished it (and its GPU), and the GPU time the worker measured. On this site's GPUs each
job shows its worker, GPU, lane, tries and times. It shows how the run was made: the model Auto picked and why, a run
Ideogram 4 declined (the asked model, the model that made it, and the picture it returned), the notices said on the
result, and each setting the model makes differently, asked and made side by side (the account's own pages show
the made value only). It shows where the run was made (the studio or tool, and whether a tool made it for one of the
account's projects), the job's id at its GPU or provider, its cost and whether it was charged, and each result's
check before it shows.

The API, for the owner only (guests get 401, accounts 403): `GET /api/admin/accounts` (each account
with `runs`, `runsDay`, `runsWeek`, `running`, `failedWeek`, `lastRunAt`, `bytes` and `capBytes`,
and `totals`; `?format=csv` for the file), `PATCH /api/admin/accounts/<id>` with
`{ "disabled": true | false }`, `DELETE /api/admin/accounts/<id>`, `GET /api/admin/generations`
(`?account=<id>`, `status=finished|running|failed`, `kind=image|video|audio|model3d|text`,
`before=<createdAt>:<id>` from the last page's `next`, `limit` up to 100),
`GET /api/admin/generations/<id>` (Run details for an account's run; 404 for the owner's own run; an admin token
needs `runs:read` and `outputs:view`, and `accounts:read` for the email) and
`DELETE /api/admin/generations/<id>` (an account's run only).

An account can delete itself: `DELETE /api/auth/me` with `{ "password" }` (an account made with Google
or GitHub that has no password: a recent sign-in with it instead, [Google and GitHub](#google-and-github)). When an account is
deleted (by itself or by the owner), its runs are stopped and removed, and its uploads and results
are deleted with it.

An account changes its password in **Settings → Account**: `PATCH /api/auth/me` with
`{ "current", "next" }` (at least 8 characters, and not the current one). Every other browser signed in to the account is
signed out; the browser that changed it gets a new session. Changing the password and deleting the
account share one limit: 5 password checks a minute per account. A browser that was signed out gets
401 from both, so the page can offer Log in; the owner gets 403.

## Your GPU

An account connects its own ComfyUI in **Settings → Your GPU**, or from the "Connect your GPU" card,
in one of two ways.

### The ComfyUI on this computer

The first choice: the account's open Fuobe tab runs its jobs on the ComfyUI on the same computer.
The server still plans every run (templates, inputs, checks, limits, history). Each ComfyUI call
becomes a job that the tab takes (`/api/gpu/computer/*`), sends to `http://127.0.0.1:<port>`,
follows, and whose results it uploads back; results are checked like uploads, and a job takes only
its own results, once. The server never calls the person's computer. Runs wait while no tab is open
("Open Fuobe on the computer with your ComfyUI to run this") and stop cleanly after a while.

- **Finding ComfyUI.** The card looks on ports 8188, 8000 (ComfyUI Desktop), 8189, 8190, 8288, 8001
  and 7821, or one the person types. While the browser would still ask to let the site reach apps
  on this device, it looks only after a click, and explains that question first. A tab never
  reaches the computer's apps by itself before that.
- **Fuobe Connect.** A page can read a ComfyUI on the computer only when ComfyUI lets that site in.
  Fuobe Connect (`integrations/fuobe-connect`, published as
  [ComfyUI-Fuobe-Connect](https://github.com/workingprototype/ComfyUI-Fuobe-Connect); a git clone,
  ComfyUI-Manager's Install via Git URL, or the Manager's search, which installs it from the Comfy Registry)
  lets in only the studios that the person trusts (`https://fuobe.com` unless they name others), and
  only for what a run needs. Every other website still meets ComfyUI's own check. It is optional.
  The card offers it while `FUOBE_CONNECT_PUBLISHED` (`src/lib/fuobe-connect.ts`) is true, as it is
  now that its repository is published: it is the one step, and the setting and the guard below are
  under "Advanced". With the switch off, the setting with the guard is the one step. See
  [gpu-workers.md](gpu-workers.md).
- **Pairing** (Safari, phones, a blocked browser, a PC with no screen), offered with Fuobe Connect:
  Fuobe Connect shows a code, and the person types it and approves it while signed in
  (`/connect?pair=1`; the page never fills in a code from its link). That ComfyUI then runs this
  person's jobs, and only theirs, with no tab open. Settings → Your GPU lists it, with Disconnect.
- **Fuobe's setting.** Without Fuobe Connect, ComfyUI must run with
  `--enable-cors-header <the site's address>`. The card gives the fix for the install it finds: a
  start file for Windows portable or Easy-Install (it restarts ComfyUI with the setting and leaves a
  start file with it for next time; it never changes the person's own start files), the place in
  ComfyUI Desktop's Server-Config, Stability Matrix's launch options, or the flag for a terminal.
  It notices by itself when ComfyUI is back with it.
- **Fuobe's guard.** With that setting, ComfyUI stops turning away other websites' requests.
  `fuobe_guard.py` (src/lib/comfy-guard.ts), a custom node that the start file puts in
  `custom_nodes` and that the other installs download from the card, puts the check back: a request
  from a web page gets in only from ComfyUI's own page or the site the setting names, the live
  socket included. It answers `GET /fuobe/guard`, and the card warns while it's missing.
- **Phones and Safari** can't reach a ComfyUI on the device: they get the link instead (and pairing, with Fuobe
  Connect), with why.

The owner can do the same on a deployed studio: **Settings → Where ComfyUI runs → On the computer
you're using**. A studio with ComfyUI on its own machine keeps calling it from the server.

### A link

For runs that go on with the tab closed. The studio's server calls that ComfyUI, so it must be
reachable from the internet. Put a tunnel in front of a local ComfyUI and paste the https address
it prints:

```bash
cloudflared tunnel --url http://localhost:8188   # or: ngrok http 8188
```

- **Saving.** `PUT /api/account/gpu` with `{ "url", "token"? }` checks the address and asks that
  ComfyUI for `/system_stats` (`?test=1` checks without saving). `DELETE` disconnects. The address
  and the optional token (sent as `Authorization: Bearer`) are stored with the account in the
  database (`auth_account_gpu`), never as the studio's ComfyUI setting.
- **Server-side requests.** Addresses on the server itself, on private networks or link-local
  addresses are refused. The check runs again on the address each connection actually uses, so a
  name that is later pointed at the server can't reach the studio's own ComfyUI. The studio's own
  ComfyUI address is refused too, and so are IPv6 addresses that wrap an IPv4 address.
  `FUOBE_ALLOW_PRIVATE_URLS=1` allows private addresses, for a LAN install, but never the server's
  own addresses. Address checks are limited to 10 a minute.
- **Runs.** Everything that runs through `POST /api/generations` runs on the account's ComfyUI
  with the open-source engine: the Image, Video and Audio studios (their input modes too: edit,
  inpaint, extend, lipsync, reframe, upscale, image to video…), every camera motion and effect,
  and the apps that take a picture, a clip or a sound. Their chained steps (multi-shot films,
  Frames mode, Extend, relit effects) run there too, as the account's own. So does a 3D model (the
  Image to 3D and Photo to 3D apps, and an image result's "Make it 3D", which opens Photo to 3D), on
  the account's own GPU or key; it is finished as Image to 3D's models are (below). On this install's GPUs
  (hosted runs), a 3D model runs only where a worker finishes it ([Hosted runs](#hosted-runs)). Polls,
  uploads, outputs and cancels go there, and nothing falls back to the studio's own providers. If
  the account's ComfyUI can't be reached, the run waits for it, then says why in plain words
  ([When your GPU or key has a problem](#when-your-gpu-or-key-has-a-problem)). A cloud model, an AI helper or
  the studio's local LLM is refused; "Enhance prompt" uses Fuobe's offline wording. Other tools
  (Canvas, Assist, Marketing…) answer 403 with `code: "own-gpu-tool"`, because they
  plan with the studio's own AI helpers or keep projects of their own. The Audio tools have their own routes (below).
  Restore & colourise (`POST /api/restore`) shows to everyone, its tab, page and result-menu item marked "Runs on your
  own GPU · 24 GB": an account runs it on its own GPU after the same checks as Genjutsu's, with Fuobe's offline template
  for the words (writing them from the frames with the studio's AI helper stays the owner's). A visitor's page is the
  GPU's whatever the engine switch says, since the cloud engine carries the gated Restore IC-LoRA, which never goes with
  an account's own key (an account's cloud run answers 422 before anything starts); a guest gets the sign-up card, an
  account without a GPU "Connect your GPU". A guest's model pickers list the
  paid models after the open ones, each marked "Use your own fal.ai key" (or Replicate); choosing one opens the sign-up
  card. An account without a key sees the same list with "Add your fal.ai key". Image to 3D's cloud models, Retexture,
  Rig and "Use the cloud" for Pick an object are marked the same way for a visitor on open models only.
  A hosted model whose calls haven't yet passed a live run with a real key (`src/lib/catalog/hosted-untested.ts`:
  MiniMax H3 Max's lip sync, relight, insert, looks and Turbo, H3 Lite and HighSpeed, Vidu Q4, the Mureka songs and
  song tools, MiniMax Music 3, ElevenLabs Music, Lyria 3.5, the hosted voice cleaners, Meshy retexture, Tripo P2,
  Fuobe Animation's cloud half, Kandinsky 6.0, Kandinsky VSR, Bria green screen and Bria guided cut-out) runs on an
  account's own key like any paid model: it stays in the account's pickers once it has a key, an account without the
  key is asked for it (`add-key`), and a guest gets the sign-up card. Audio → Extend & remix shows to everyone, its tab
  marked "Use your own fal.ai key". `src/lib/own-setup.ts` labels these and every other item that runs only on a
  visitor's own GPU or key (`ownSetupOnly`, `ownSetupLabel`, `ownSetupStep`), and the hosted runs never place one on
  this studio's GPUs or keys. The items that need a bigger card than this studio's (Open-H3 Regenerate: Upscale →
  Video's "Regenerate · creative" and its first step, "Regenerate in 2K" and "Enhance" in result menus, the Canvas
  node, Shorts' Enhance, Cinema's "Finish in 2K" on a GPU take, MiniMax H3 at 2K on
  your GPU, Character Swap's Sharpen and its 1080p / 2K / 4K on your GPU; and Kandinsky 6.0 Pro) show to everyone,
  marked "Runs on your own GPU · 48 GB" (Kandinsky Pro's choice says about 80 GB). An account runs them on its own GPU
  only, when that GPU has the memory (`src/server/own-setup-run.ts`); otherwise it gets "Connect your GPU" (`connect-gpu`).
  Cinema's and the Video studio's exact orbit are marked "Runs on your own GPU · 48 GB or fal.ai key". Faceless's
  "Regenerate to 1080p" and Shorts' Enhance run on an account's own GPU through their own routes (`.../regenerate`,
  `.../enhance`). The owner sees these surfaces too; while they are held on this studio's GPU, the owner's run answers
  with what it needs ("needs a GPU with 48 GB or more"). Cinema's "Make a prop from a picture" (Idol 3D) runs on a
  visitor's own GPU through Image to 3D's route. MiniMax H3's "Fast decode", once it is offered, carries its label in
  the same way.
  "Write the lyrics" and "Rewrite my prompt now" use the studio's AI helper and are hidden from guests and accounts.
  A song's stems come back as one zip: for an account it is fetched from public addresses only, within what its files
  have room for (128 MB at most, 256 MB unpacked), and each stem is saved to disk as it is unpacked.
- **Genjutsu.** An account runs Genjutsu's modes that are open to everyone the same way (`POST /api/genjutsu`, and the
  clip's words for Character swap, `POST /api/genjutsu/transcribe`). Each step of the run (the cut, the swap, the joins,
  the sound) is a run of its own on the account's ComfyUI, or on its own fal.ai or Replicate key on the cloud engine,
  with only its own files, and the whole run counts once against its limits. Its results show under "Your Genjutsu" and
  in its own runs, to open and download. "Describe my character" (`POST /api/genjutsu/describe`) runs the GPU describer
  on the account's own ComfyUI: a core graph (Qwen3-VL 8B through TextGenerate, `character-describe-qwen3vl`) reads
  only the account's own picture, takes no text from the request and saves under a name the server makes; the page
  fills the description from that run's text. A guest gets the sign-up card. The checks are
  `src/server/account-tool-run.ts`.
  The modes and options that haven't yet passed a real render on this studio's GPU (Group swap's "one by one", Object
  swap's Change it, Remove it and New background, From picture with its Light and own person choices, Fix faces and
  MiniMax H3 Motion transfer) show to everyone, marked with what they run on ("Runs on your own GPU · 24 GB",
  `src/lib/own-setup.ts`). An account runs them on its own GPU; without one it gets "Connect your GPU"
  (`connect-gpu`). The mark leaves by itself once the feature's graphs are validated and its pass is recorded in
  `workflows/comfyui/gpu-tested.json` (`genjutsuLive`; "Clean the voice first", in Genjutsu, Character Swap Studio,
  the studios and Captions, works the same way through `soundLive`). The same holds when these makers are sent
  straight to `POST /api/generations`. Cinema Studio's World mode carries the same mark
  until its graph is validated (`src/server/own-setup-live.ts`), and Image to 3D's "Trim spikes" says what it runs on.
- **Storyboard.** An account makes boards the same way (`POST /api/storyboards`), and the film of a board
  (`POST /api/storyboards/<id>/film`). Every frame, shot and join is a run of its own on the account's ComfyUI, or on
  its own fal.ai or Replicate key on the cloud engine, with only its own pictures as look references, and a board (or
  a film) counts once against its limits. Its boards are its own runs: the page lists them, to reopen, open and
  download, and a film takes only its own board (another account's board, or the owner's, answers 404 "We can't
  find that storyboard."). "From one idea" splits the story into a shot list without the studio's AI helper. One
  sheet takes as many panels for an account as its recorded GPU test showed (`ONE_SHEET_GPU_TEST`; with none recorded
  a one-sheet board answers 422 for an account). A guest gets the sign-up card.
- **Image to 3D.** An account makes its 3D models on its own ComfyUI, or on its own fal.ai or Replicate key on the
  cloud engine (`POST /api/image-to-3d`, which takes the same request as `POST /api/generations`): From an image, From
  several images, From text, Pick an object and Splat, and a finished model's Rig & animate. It gets the checks every
  tool run gets, and its models show under "Your 3D models", to view in 3D and download. A GLB from its ComfyUI is
  finished on this server (the web GLB the viewer loads) under its limits (`src/server/model3d-finish.ts`): one account's
  finish at a time across the server, at low priority; a model over 300 MB, a server or account short of room, or more
  than 60 finishes in an hour keep the model as it came (still viewable and downloadable). Its turntable is recorded in
  the browser ("Record turntable"), not on the server. Film it photoreal runs as a Fly around (below). Refine detail (Hi3D), the TRELLIS.2 final,
  Idol 3D's other sides ("Make the other sides from the front") and Trim spikes show to everyone and run on the
  account's own GPU through the same route; each is labelled with what it runs on ("Runs on your own GPU · 24 GB")
  until its graph is validated on this studio's GPU (`graphs` in `src/lib/own-setup.ts`, read by the page with
  `ownSetupsNow`, `src/server/own-setup-live.ts`), when the label leaves by itself. Retexture and Rig run on the
  account's own fal.ai key. On this install's
  GPUs (hosted runs), Image to 3D and Refine detail run only where a worker finishes the model
  ([Hosted runs](#hosted-runs)). A guest gets the sign-up card.
- **Character Swap Studio.** An account keeps Character Swap projects of its own (`/character-swap`; `GET`/`POST
  /api/swap-studio/projects`, `GET`/`PATCH`/`DELETE /api/swap-studio/projects/<id>`): its own only (another account's,
  or the owner's, reads as 404; a guest gets the sign-up card), up to 50 of 1 MB each and 120 saves a minute, deleted
  with the account. Every job in a project (a clip's 24 fps copy or browser copy, its words, a mask, a scene anchor,
  queued takes, Sharpen, the assembly) is a run of its own on the account's ComfyUI, or on its own fal.ai key on the
  cloud engine, with only its own uploads and results, after the same checks as Genjutsu's. A queue counts once against
  its limits: a take that waits for the one before it starts later in the same run. The pictures a project names (the
  character, an imported anchor) and its clips are the account's own. Its assembled clips are its own runs, to open and
  download. The checks are `src/server/swap-studio-account.ts`.
- **Shorts Studio.** An account makes its own shorts the same way (`POST /api/shorts/sessions`), on its own ComfyUI or
  on its own fal.ai or Replicate key on the cloud engine: each segment's cut, restyle and the stitch under the clip's
  sound are runs of its own, with only its own files, and a short counts once against its limits. A new take of a
  segment (`POST /api/shorts/sessions/<id>/segments/<n>`) and Stitch again (`.../stitch`) go through the same checks.
  Its shorts and the presets it makes from its own pictures are its own projects (`src/server/account-projects.ts`):
  its History, a short's page (`/shorts/<id>`) and its preset list show only its own, and another account's or the
  owner's read as not found (404). It keeps up to 50 shorts. Deleting a short deletes its runs for good (an account
  has no Trash). It downloads the full video, each part, and "Download parts" as one zip of its own runs.
  Enhance (`.../enhance`, Open-H3 Regenerate) runs on its own GPU only, one with 48 GB or more (`connect-gpu`
  otherwise), after the same checks. A guest gets the sign-up card.
- **Cinema Studio.** An account makes, reopens and runs its own projects (`/api/cinema/projects/**`): up to 50,
  each with its folders, takes, Director settings, brief and AI Director chat, deleted with the account. Another
  account's project, or the owner's, reads as not found (404), and the owner's lists never show an account's. A take
  (`POST .../generate`, World mode and Blockout to film included), a retry (`.../items/<id>/retry`) and a 2K finish
  (`.../items/<id>/finish`) run the same way as Genjutsu's: every step on the account's ComfyUI or its own fal.ai or
  Replicate key, with only its own files, after the same checks. A project's cover and a grid's tiles must be its own
  files. Its AI Director writes the shot breakdown without the studio's AI helper (no GPU or key needed). Its Delete
  deletes a take for good (it has no Trash). "Create 3D scene" and an exact orbit run there too: on its GPU their first
  step is a 3D model, finished on this server under its limits as Image to 3D's are. Saving a still as an element, the
  elements list and sharing a project are left out: those are the owner's library. A guest gets the sign-up card.
- **Photodump, Fashion Factory, Character Sheet and AI Influencer.** An account runs them the same way
  (`POST /api/photodump`, `/api/photodump/fashion`, `/api/photodump/character`, `/api/influencer`, and a photo's retry
  `/api/photodump/retry`): every photo on its own ComfyUI or its own fal.ai or Replicate key, with only its own files,
  after the same checks, and a set counts once against its limits. Its packs (`/api/photodump/packs`) and its
  characters (`/api/photodump/characters`: a name and photos of one person, saved from New character or from a
  Character Sheet's "Save as character") are its own projects: up to 50 of each, from its own photos, deleted with the
  account; another account's or the owner's read as not found (404). An account's character goes into a run as its
  first photo (an @mention names the owner's elements only). Its runs are its own (each tool's History and recent
  sheets), and a retried photo replaces the failed one for good (it has no Trash). The price is its run's: free on its
  GPU, its own key's price on the cloud engine. A guest gets the sign-up card on Generate, on Create pack, on New
  character and before choosing a photo.
- **Video tools, Turnaround video, Fly around and Katana.** An account runs Remove object and Remove a person
  (`POST /api/remove-object`, its mask preview `.../preview` and "Redo from here" `.../reroll`), Evolution
  (`POST /api/evolution`), Mixed Media (`POST /api/mixed-media`, a preview frame `.../preview` and "Try again"
  `.../retry`), Turnaround video (`POST /api/turnaround`), Fly around (`POST /api/fly-around`: Image to 3D's "Film it
  photoreal" and the exact orbits) and Katana (`POST /api/katana`, `.../<id>/retry`) the same way as Genjutsu's: every
  step on the account's ComfyUI or its own fal.ai or Replicate key, with only its own files, after the same checks, and
  a run counts once against its limits. Their price checks are priced for the account's own GPU or key. Their results
  are its own runs (each tool's history, "Your …" feeds and its runs list), to open and download. "Redo from here" and
  "Try again" take only its own removal or render, and a Mixed Media render's frame count (`GET
  /api/mixed-media/progress`) answers for its own renders only (anyone else's reads as 404). Evolution's direction
  (`POST /api/evolution/direction`, and a run sent without one) is written by Fuobe's offline writer, never the studio's
  AI helper. Turnaround and Fly around never use the studio's WorldCast worker for an account; a character from the
  owner's library answers 404. Katana's runs are its own projects (`GET /api/katana`, `GET`/`DELETE
  /api/katana/<id>`): up to 50, another account's or the owner's read as 404, deleted with the account. A guest gets
  the sign-up card. Removing a person with MiniMax H3 and VOID's removal on the open engine keep their "own setup"
  entries (`video-tools:remove-person`, `video-tools:remove-object-void` in `src/lib/own-setup.ts`) until a real render
  passes on this studio's GPU and is recorded in `workflows/comfyui/gpu-tested.json` (`remove-person`,
  `remove-object-void`): their graphs' `validated` in the manifest says only that ComfyUI accepted the graph.
- **Restore & colourise.** An account runs it (`POST /api/restore`) on its own GPU, the same way as the Video tools:
  every window, join and the sound put back on its own setup, with only its own clip and reference picture, after the
  same checks. The prompt is the account's own words, or Fuobe's offline template filled with its few words. The prompt
  writer (`POST /api/restore/prompt`) stays the owner's, because it uses the studio's AI helper. A cloud run is refused
  before anything starts, with one sentence that says to switch to the open engine: the gated Restore IC-LoRA never goes
  with an account's own key. Its price check (`POST /api/restore/estimate`) is priced as the account's run would go, on
  its own GPU. With hosted runs on, an account without a GPU gets the "own setup" label (`video-tools:restore`) in the
  price check, and Run opens that setup. A guest gets the sign-up card.
- **Audio tools.** An account runs Split soundtrack and Clean up dialogue, Video tools → Remove dialogue, Edit speech,
  Loop / extend, Join and Clean up voice (`POST /api/audio-tools`) the same way as Genjutsu's: every step on its own
  ComfyUI, or on its own fal.ai or Replicate key where a step is a cloud model, with only its own files, after the same
  checks, and a run counts once against its limits. Its price check is its own run's. Its stems, clean dialogue,
  edited speech and mixes are its own runs, to reopen in the mixer, open and download, and Export mix keeps the WAV as
  one of its runs (above). Edit speech runs on the account's own GPU only (AuK's files and a 24 GB card): its tab and
  page carry the "own setup" label (`audio:edit-speech`), and its upload and run ask an account without a GPU to
  connect one. Result menus offer Remove dialogue, Clean up dialogue and Edit speech, and Captions offers "Fix this line".
  A guest gets the sign-up card.
- **Palette lock.** An account's palette lock (`POST /api/palettes/lock`: its images, then each one recoloured to the
  palette) runs on this install's GPUs only, with hosted runs on, after the same checks, and with no more pictures at
  once than a run there makes. A run on the account's own GPU or key keeps its colours in the prompt, as before: the
  composer sends no lock there, and the route and the proxy refuse one (`own-gpu-tool`).
- **Translate & dub.** An account keeps dubs of its own (`GET`/`POST /api/dub`, `GET`/`PATCH`/`DELETE /api/dub/<id>`,
  `POST /api/dub/<id>/voice`): up to 50, in the account project store, deleted with the account. Another account's dub,
  or the owner's, reads as not found (404), and the owner's list never shows an account's. A dub (one shot on its own
  key, or step by step) and the voice of each language run the same way as Genjutsu's: every step on its own ComfyUI
  or key, with only its own video. Its translations run on its own GPU (Qwen3.5 4B, `oss-qwen35-translate`), never on
  the studio's AI helper, on either engine: a cloud step-by-step dub with a key and no GPU is asked to connect one. Its
  reviewed lines are saved with its dub, and its dubbed videos are its own runs, to open and download. A guest gets the
  sign-up card.
- **Faceless Studio, the Explainer and Content Factory.** An account's channels (`/api/faceless/channels/**`), their
  episodes (`/api/faceless/episodes/**`), its explainers (`/api/explainer`) and its series
  (`/api/content-factory/series/**`) are its own (`src/server/account-projects.ts` kinds `faceless`, `explainer` and
  `content-factory`; up to 50 of each, deleted with the account). Another account's, or the owner's, read as not found
  (404), and the owner's lists never show an account's. Its scripts, episode plans, channel names, topic ideas and
  document summaries are the offline writer's: never the studio's AI helper. A render, a retry, a timeline change, an
  upscale, a channel avatar, a narrator sample and a reference clip's reading run on its own ComfyUI or its own fal.ai or
  Replicate key, with only its own files, after the same checks as Genjutsu's (`src/server/account-tool-run.ts`); the
  whole render is planned and checked before its first step starts, and a series' episodes render as one run. Writing a
  script for review, a channel and a series made from a preset need no GPU or key. The server never fetches a link for
  it: a channel's YouTube reference is kept as the link, and an explainer's link source and a series' TikTok or
  Instagram link are the owner's (it attaches the file or uploads the clip). "Generate in Claude" (the studio's own MCP
  server) isn't offered to it (403 `own-gpu-tool`). "Regenerate to 1080p" runs on its own GPU only, one with 48 GB or
  more (`connect-gpu` otherwise). A guest gets the sign-up card.
- **Files a run takes.** A run on your GPU takes only files you uploaded here, or your own results.
  A link or a `data:` URI answers 400 with `code: "input-not-allowed"`, someone else's file 403
  (`input-not-yours`), and a file that has expired 404 (`input-gone`, "That file has expired.
  Upload it again."). A file bigger than an upload of its kind may be (one of your own results,
  too) answers 413 (`input-too-big`). The server never fetches a link for an account. The one
  exception is Fuobe's published example files ("Start from an example" on a page): a run may read
  them by their exact path, the same for everyone, from the server's own disk, with no upload and no
  space used. Nothing else outside your own files. A published example file is never removed or renamed.
- **LoRAs and model files.** The server never downloads anything onto your machine. A LoRA a run
  adds (a camera motion's, an effect's, a look's) must already be in your ComfyUI's `models/loras`
  folder. When one is missing, the run answers 409 with `code: "comfy_missing_model"` and a `fix`
  that lists each file, the folder it goes in and where to download it ("Your ComfyUI doesn't have
  2 LoRA files this needs. Download each one into ComfyUI/models/loras, keep the file name, then
  press Generate again."). The same check runs again when the run is handed to your ComfyUI. A
  checkpoint or encoder your ComfyUI lacks is named by ComfyUI's own answer.
- **Limits.** Up to 4 runs at once and 60 an hour; a run makes up to 4 results. A run waits up to
  30 minutes in your ComfyUI's queue and may run for 45. Your ComfyUI's answers have a deadline and
  a size cap (a result up to 1 GB in 15 minutes, and no more than your files have room for; 16
  results a job at most). Each account sends one file to its ComfyUI at a time, and the accounts
  take turns. The clip check (`POST /api/media/probe`) allows 60 a minute and 2 at once.
- **Disk space.** Accounts can't upload or run when the server's data disk is short of space
  (503): it keeps 20 GB free, or a tenth of a smaller disk, and at least 2 GB.
  `FUOBE_ACCOUNT_DISK_FREE_GB` sets another amount, and the server log says when accounts are
  refused for space.
- **What a visitor sees.** For a guest or an account, `GET /api/status` describes its own GPU
  (`viewer`), with the open engine and no Demo mode. It says nothing about the studio's own
  ComfyUI, providers, keys or local AI servers. The account menu (the top bar's right end; the You
  tab on a phone) shows **Your GPU · Connect** (a guest signs up first), or the account's ComfyUI as
  online or offline with its GPU and VRAM, then Settings and the light or dark switch. An
  account's menu also shows its email, Your GPU (`/connect`) and Sign out. Thanks & licences and
  the source on GitHub are in Settings → About, for guests and accounts too.
  `GET /api/models` lists the open-source models for a visitor, and the studios price a visitor's
  run as it would go on its own GPU. The studio's own settings page isn't shown to visitors.

### Set it up with my AI

An account can let its own AI (ChatGPT, Claude, or a coding agent such as Claude Code, Codex or
Gemini CLI) do the setup: **Set it up with my AI** on the Connect your GPU card, in Settings → Your
GPU and at `/connect?setup=ai`. A guest who opens that link gets **Log in** first, for the account it
started with (most often on a phone), then **Sign up free**. Both come back to the same link, its
way included. The panel picks the
way for the browser (Fuobe Connect first while it is published, then this browser, or a web address
on Safari, on a phone and on a page on plain http), gives the AI a short message with two links (the
steps and the status), and ticks off each step as the account's open tab sees it. It ends with a
first picture made on the account's GPU. `/connect?setup=ai&way=address` opens the panel on the web
address, with the box for it in focus.

- **Fuobe Connect.** The steps install it from its repository: a `git clone` into `custom_nodes`,
  or its `.zip` or `.tar.gz` download where git is missing, then a restart of ComfyUI (ComfyUI
  Desktop, the portable build, Stability Matrix, a terminal, or a service on Linux). They say that
  ComfyUI-Manager's search may offer no version to install, they count its install (the folder
  `fuobe-connect`) as installed, and they make sure that ComfyUI answers `GET /fuobe/connect`. In Chrome, Edge or Firefox on that computer, the tab connects by itself once
  Fuobe Connect answers. On a phone, in Safari, on a page on plain http or in a browser that blocks
  the computer, the panel shows the box for the code that ComfyUI's **Connect to Fuobe** shows, and
  the setup is done once the paired ComfyUI is heard from (in the last minute). On a self-hosted
  studio, the steps add its address to Fuobe Connect's list.

- **From a phone.** The commands run on the computer, so the tunnel's address lands on the
  computer's clipboard. The status, the steps and the phone's panel send the person to
  `/connect?setup=ai&way=address` on that computer, signed in to the same account: the box for the
  address is there, under the same setup code (a different code means another account). Until
  Fuobe has an address, the status's next step is the tunnel even while the phone's tab sleeps.
  The phone has one **Send to my computer** button (**Copy link for my computer** where the
  browser can't share). It sends `/connect?setup=ai` with the way the phone is on: `way=address`
  for a web address, `way=connect` for Fuobe Connect. The computer opens on that same way.
- **ComfyUI starting again.** When ComfyUI stops answering on this computer, the panel and the
  status say it is starting again for up to 5 minutes (a portable or Easy-Install ComfyUI loads
  every add-on first), with the minutes so far. After that they say it didn't come back: look at
  its window, or start it again.
- **On the processor.** A ComfyUI with no graphics card (its device is `cpu`) is named as such on
  every way, the web address included, with what it means: no picture model fits, and a picture
  would take many minutes.

- **The code.** `POST /api/setup/session` (`{ way, os, phone?, fresh?, resume? }`) gives the
  account one setup code of 12 letters and digits, like `ABCD-EFGH-JKMN`. The same call again
  answers the same code. The code ends 30 minutes after the account's tab was last heard from (2
  hours at most), 10 minutes after the setup is done, when the account makes a new one (`fresh`),
  or at once with **End this code** (`DELETE /api/setup/session/<code>`). It also ends when the
  account is deleted or switched off. The codes live in the server's memory. After a restart, the
  account's tab brings its own code back with a resume token sealed for that account.
- **The tab.** The account's open tab reports what it sees
  (`POST /api/setup/session/<code>/report`, fixed values and whole numbers only, unknown keys answer
  400) and waits for its AI's reads (`GET /api/setup/session/<code>/wait`, 25 seconds at most). One
  tab leads a setup at a time: the tab opened last, or a tab in view once the leading one closes, hides
  or goes quiet. Another account's code answers 404.
- **The status.** Anyone with the code can read `GET /api/setup/<code>` without signing in: the
  steps, the port and the kind of install, and the next step, in fixed words (plain text, or JSON
  with `?format=json`). It never holds the email, a run, a key, an address, a token, a file name or
  the GPU's name. Reading it reaches only the server's memory: at most it asks the open tab to look
  at its own ComfyUI sooner, once every 3 seconds. Every code that is not active gets the same 404.
- **The steps.** `GET /api/setup/guide/<way>/<computer>` (the steps for the AI, with the studio's
  own address from a fixed list: fuobe.com, `FUOBE_ALLOWED_ORIGINS`, or an address on the local
  network), `GET /api/setup/files/fuobe_guard.py` and `GET /api/setup/files/start/<port>` (the
  Windows start file) are open to everyone. The steps tell the AI to show each command and wait for
  a yes, to use exactly `--enable-cors-header <the studio's address>`, never `--listen`, and to
  check Fuobe's files by their SHA-256. For Fuobe Connect, they add no start setting and install only
  Fuobe Connect, from its repository. For a web address, they run the tunnel in a window the
  person sees, keep its log where only that user can read it (`~/.fuobe` on a Mac or Linux,
  `~\.fuobe` in the user's own folder on Windows), warn when ComfyUI-Manager is
  installed (anyone with the address can use it), and stop the tunnel when the person is done. When
  the address asks for a password or a token, they keep it and put it in Fuobe's Access token.
- **Limits.** 6 new codes a minute and 20 an hour per account. 30 status reads a minute per code.
  Unknown codes: 10 per 10 minutes per visitor and 600 per 10 minutes for everyone together. The
  visitor is the client behind a trusted proxy (`FUOBE_TRUST_PROXY=1`), else the last
  `X-Forwarded-For` hop a proxy in front set: a made-up hop only moves its own reads to another
  budget, the shared one still holds, and an active code never uses either. With no proxy at all,
  only the shared budget applies. The steps and Fuobe's files: 60 a minute per visitor
  (behind a trusted proxy), and no budget shared by everyone, so no visitor can use up another
  person's. All answer 429 with `Retry-After`. Past the budget for unknown codes, the answer still
  tells the AI to ask the person for the code Fuobe shows now: a code that is active works at once,
  and the wait is only for a person with no new code.

The code is `src/server/ai-setup.ts`, `src/lib/ai-setup/`, `src/components/gpu/ai-setup/` and
`src/app/api/setup/`.

## Your keys

An account can add its own fal.ai key or Replicate token in **Settings → Your keys** (below Your
GPU), or from the "Add your key" card that opens when it picks a paid model it has no key for (a
search in a model picker lists them, dimmed, and a link to one keeps it, with a note), from the
locked engine switch, or from "No GPU?" on the welcome page and the Connect your GPU card. With
a key it runs that provider's paid models (Nano Banana, Seedream, Kling, Veo…), billed to its own
account with that provider. The studio's own keys are never used for an account's run.

- **Checked first.** `PUT /api/account/keys/fal` (or `/replicate`) with `{ key }` checks the key
  with the provider before it is saved: a free call that runs nothing (fal.ai: the status of a
  request that doesn't exist; Replicate: `GET /v1/account`). A refused key answers 422, a provider
  out of reach 503, and nothing is saved. A key that works on a provider account with no balance
  left is saved, with a `note` that says to top it up. `?test=1` only checks. Only a check that
  reaches the provider counts: 10 a minute per account, 20 per address (behind a trusted proxy),
  120 for all accounts together.
- **Stored encrypted.** The key is sealed with AES-256-GCM under a server key in
  `data/secrets.key`, made the first time a key is saved, and kept with the account in the
  database (`auth_account_keys`). The server key isn't derived from the sign-in secret, so a new password or "Sign
  everyone out" leaves saved keys working. Without `secrets.key` (lost, or restored from another
  server), saved keys can't be opened: accounts are asked to add them again, and the studio's keys
  are never used instead.
- **Never shown.** `GET /api/account/keys` gives each key's last 4 characters, when it was added,
  whether this server can still open it, and whether the provider refused it in a run. No answer,
  log or error holds a key: a provider's error that echoes the request has it replaced with "••••".
  The owner's **Settings → Accounts** shows which providers an account has a key for (the CSV has
  `fal_key` and `replicate_key`), never the key.
- **Removed with the account.** Deleting an account (by itself or by the owner) switches it off,
  stops its running jobs at the provider with its own key, then removes its runs, files and record,
  keys included. Removing or replacing a key that runs are going on answers 409 `runs-going` first;
  with `{ stopRuns: true }` those runs are stopped with the old key before it changes. A run still
  being handed to the provider is stopped there when its submit lands: the key (or the deleted
  account's record) waits for that, up to a minute. On an install upgraded from `auth.json`, the
  backup `auth.json.migrated-<time>` still holds the accounts as they were at the upgrade, sealed
  keys included: delete it once the upgrade is confirmed ([Sign-in data](SELF-HOSTING.md#sign-in-data)).
- **What it changes in the studios.** `GET /api/status` lists the account's keys
  (`viewer.keys`) and its engine mode: `both` while it has a key and the studio isn't open-source
  only, else `open`. The model pickers dim the paid models it has no key for ("Add your Replicate
  key"), and prices say who pays ("≈ $0.15 · your fal.ai account"). A paid run without the key
  answers 403 with `code: "add-key"` and an `x-fuobe-add-key` header naming the provider.
- **Limits.** Every account limit applies to paid runs too (4 at once, 60 an hour, 4 outputs a run,
  its space), checked before anything reaches the provider. Runs with a key send the prompt and the
  attached files to that provider. civitai LoRAs are left out of runs on an account's key (copying
  them would use the studio's civitai key). Image to 3D runs on its key too; Assist, text steps and the other tools stay closed.
- An account on a studio set to **Open source only** keeps its keys, but they aren't used.
- **Balance and account.** Each saved key's card shows what the provider tells about the account
  behind it, and the account menu (the You sheet on a phone) has **Connected accounts**: one row per
  key with its balance, or **Add a key** when the account has none. `GET /api/key-info`
  (`src/server/provider-account-info.ts`) asks fal.ai's account billing call (the balance and the
  account's name, for a key with the `billing:usage:read` permission; fal.ai's default API keys
  get a link to the billing page instead) and Replicate's `GET /v1/account` (the account; Replicate
  has no balance call, so its row links to its billing page). Both are reads that run nothing. The
  route reads the key through `cloudKey` inside the account's own work, so an account only ever
  gets its own keys' answers. The owner gets the studio's keys, and a guest gets 401 before any key
  is read. Nothing is asked on page load: the menu asks when it opens, and Settings when the card
  scrolls into view. An answer is kept 60 seconds (15 when the provider is busy or out of reach),
  and **Refresh** asks again at most once every 10 seconds per key. The answer holds only the
  balance, the account's name and the state, never a key, its last characters or the provider's
  own words. A check here never marks a key refused or its balance empty.

## When your GPU or key has a problem

An account's GPU can be off, starting up, or behind a password. Its key can be refused, or its
provider can be busy. In each case the account sees one plain sentence that says what is wrong
and what to do, a small details line for the curious, and buttons that help. The details line
names the kind of address ("RunPod pod, port 8188", "your tunnel", "your web address"), never the
address itself, with the status and the reason; a token or key the answer echoed is taken out.
`src/lib/diagnose.ts` reads every failure the same way, for Settings, the composer and a run. The
owner's own runs, and runs on this studio's GPUs (hosted runs), keep their words as before.

- **Settings → Your GPU.** Test and Connect say what is wrong with the address: a RunPod pod that is
  stopped ("Your RunPod pod isn't running, or ComfyUI isn't on port 8188", with **Start your pod**,
  a link to RunPod's pods page), a pod that is on while ComfyUI starts, a GPU starting up, no
  answer, a password that is missing or wrong, a sign-in page in front, or another app on that
  address. `PUT /api/account/gpu` answers 422 with `error` (the sentence) and `trouble` (`cause`,
  `details`, `actions`, `retryable`). An address pasted without `https://` gets it added, and a
  `?…` or `#…` part is left out; the answer's `note` says so. An `http://` address that sends to
  the same host's `https://` is followed to the port it named. A GPU that is off or starting up is
  checked again by itself (5, 10, 20, 30 seconds, for 3 to 5 minutes). After Test, which saves
  nothing, the words say to press **Connect** once it answers; when the checks stop, they say so,
  with **Check again** and **Save anyway** (`{ "anyway": true }`, which keeps the address: runs wait
  for it). Too many checks (429) count down and check again by themselves. The saved address's card
  says **Offline** with the reason, and **Check now** (`{ "saved": true }`) asks it again. A local
  address (`localhost`, a home network) offers **Use this computer** where this browser can reach
  its ComfyUI, and **Pair with a code**. Where it can't, a line says why instead ("Use this computer
  works in Chrome, Edge or Firefox. Safari doesn't let a website reach programs on your Mac.", or on
  a phone or tablet, or a page the browser marks as not secure).
- **Settings → Your keys.** A key whose provider account has no balance left shows **Add credit**
  (a link to the provider's billing page) instead of **Ready**, with the day it ran out. A saved key
  has **Check again** (`PUT /api/account/keys/<provider>` with `{ "recheck": true }`): the provider's
  free check, run on the saved key, which clears a refusal or an empty balance once the provider
  takes the key. A check that finds the provider busy or out of reach (429 or 5xx) asks twice more
  by itself, then says "fal.ai is busy right now, so we couldn't check your key. Try again in a
  minute." with the status in `details`. A run the provider takes on the key clears both marks too.
- **Before Run.** When the account's GPU didn't answer its last status check, the composer shows
  the reason and its buttons above Generate. It reads the status the strip already has (every 30
  seconds), so the GPU is never asked more often. Its words say what happens to runs ("Start your
  pod, and your runs start as soon as it answers. A run you start now waits for it."); a problem
  waiting can't fix (a password, another app on the address) says "Runs can't reach your GPU until
  this is fixed." When one of the account's keys runs the tool's cloud version (a preset's cloud
  route, or a Fuobe Original on the cloud engine), **Run with your fal.ai key** sits right after the
  first fix. It runs this one run there, billed to that key, and leaves the engine switch where it
  was: the next run goes to the GPU again. A key the provider refused, or whose balance ran out, is
  not offered. A paid model on a key whose balance is empty (found on a run, or by a check of the
  key) says so above Generate ("Your fal.ai balance is empty. Add credit there, then run."), with
  **Add credit**. A graph that needs a second ComfyUI (ThinkSound, LatentSync 1.6) says so before Run, with
  **Run with your key** when one runs its cloud version, and **Pick another model**. The account
  menu says why the GPU is offline: "pod stopped", "starting up", "needs a password".
- **A run that waits.** A run whose GPU is off, starting up or out of reach waits and tries again by
  itself, with a growing wait (up to a minute between tries, or what the other side asked for).
  Before each try it asks the GPU's `/system_stats` only; its files go once the GPU answers, and a
  file already sent is never sent twice. Its tile says what it waits for ("Your RunPod pod is off.
  Start it, and this run goes on by itself", "Waiting for your GPU to start up"), until when it
  waits, and the buttons that help (**Start your pod**, **Check my GPU**, **Run with your fal.ai
  key**, which moves this run to the key: it stops waiting and the cloud run takes its place). A run
  that made several jobs (a batch) moves as one: the press stops every job of it not handed over yet
  and the cloud run makes their outputs, never the whole batch again; while it is on its way the
  batch's other tiles don't offer the button, and a later press on one of them answers 409 "This run
  has already started or stopped, so nothing new was run." (`replaces` beside the request names the
  run). A step of a longer run (a relight and then its clip, a film's shot, a Mixed Media step), or a
  job of a batch whose other waiting job a later step waits for, doesn't offer it: moved alone, the
  step would stop and the rest of the run would go without it. Its wait goes on, and `replaces` on it
  answers 409 "This step is part of a longer run, so it can't move to your key on its own. It goes on
  by itself, or cancel it and run the tool again with your key." (`chained-run`). Nor does a run a
  tool made for one of the account's projects (a Cinema take, a Storyboard board, a short, a Faceless
  or Content Factory run), even a take of one step: moved alone, it would leave its project, where it
  would show Canceled. `replaces` on it answers 409 "This run is part of one of your projects, so it
  can't move to your key on its own. It goes on by itself, or cancel it and run it again in its
  project with your key." (`project-run`). Only a run made on its own (`POST /api/generations`, as a
  studio's Generate makes it, or Image to 3D) moves: the server marks it so when it makes it, and the
  tile offers the button only where a press can act. The Library's card shows the same buttons. Each cause has its own time from when it was first seen: a
  GPU that is off 30 minutes, one starting up 10 minutes, and 40 minutes in all. Before the run
  fails, the GPU is asked once more. When the account saves a new address (or password) while a
  run waits, the run goes there; when it disconnects its GPU, the run stops and says so, with
  **Connect your GPU**. A provider that is busy (429) or down (503) at submit is tried again for 1
  to 3 minutes; a 502 or 504 at submit is not, because the job may have started. The same holds on
  the GPU: a failure at ComfyUI's `/prompt` is tried again only when it proves nothing arrived
  (nothing listening, no such name, a stopped pod, a tunnel that is down). Waiting never retries
  what it can't fix: a refused key, an empty balance, a missing add-on or file, or an input the
  model refuses. A 403 that isn't about the key (a model the key may not run) says to pick another
  model; the key stays as it is. A wait is kept with the run (`external_meta_json`), and the server
  that waits holds the run's turn to send it (`submit_turns`, the same turn every run has; each
  app process says every 5 seconds that it still runs, and the turn of one that has said nothing for
  20 seconds is free): after a restart, or when a deploy's new instance takes over, the run goes on
  with what is left of its wait (its tries and its time), on one instance only; so does a step of a
  longer run. Another instance never fails, takes or sends a run whose turn a running instance
  holds. A server that is stopping sends no more tries and gives its waiting runs' turns back at
  once, for the next instance; it launches no new step of a longer run and takes over no wait,
  and a step whose first send it had begun is left unsent, for the next instance to launch. A run that
  waited, and a step of a longer run on any try (its first too), is marked just before the try sends
  the job itself: a server cut off in the middle of that send leaves a job the GPU or provider may
  already have, so the next instance doesn't send it again, and the run fails with "This run was
  interrupted while it was being sent. Press Retry." Its tile doesn't say **Not billed**, because
  the provider may have the job. A try the provider turned down as it was sent (a refused key, an
  empty balance, a model gone: a 4xx answer) still says **Not billed**. A run planned for
  another provider by then stops in plain words. Runs that wait for the GPU count apart from the 4
  runs at once (up to 4 more wait); a fifth waiting run answers 429 "You have 4 runs waiting for
  your GPU. Cancel one, or run one with your key, to start another." Runs that wait on a key (its
  provider busy or down) count among the 4 runs at once.
- **A paired ComfyUI.** A run for a ComfyUI paired with a code (Fuobe Connect) that is off says
  "Waiting for your paired ComfyUI. Start ComfyUI there (or start your pod), and this run goes on
  by itself." It doesn't ask for a Fuobe tab, because a paired ComfyUI needs none. A Fuobe tab
  that runs this computer's ComfyUI and is signed out says so, with **Log in**.
- **While it runs.** A GPU or provider that stops answering mid-run is asked again with a growing
  wait (what it asked for in `Retry-After` up to 2 minutes, never past the run's own time), and
  after 3 misses the tile says "Your GPU stopped answering. Waiting for it to come back".
  On the account's GPU it stops after 15 minutes in plain words. On a key the job is accepted (and
  paid), so it waits on until the run's own time limit; a call to fal.ai or Replicate that hangs is
  given up after 20 seconds (60 for a submit or a result) and asked again. A key refused or a
  balance gone while a run is polled fails it at once, and the job is stopped there. A ComfyUI that
  restarted and lost a run gets it sent once more, as the same job of its batch (its own seed). A
  run whose account moved to another address says so. A job in the GPU's queue waits as long as
  the queue keeps moving (2 hours at most): its place gets nearer the front (the jobs before it are
  the ones with a lower number in ComfyUI's queue), or the GPU starts another job ahead of it. It
  stops when nothing has moved for 30 minutes (45 while a job runs ahead of it, the time one job
  may take), saying the GPU was busy. A made result whose copy breaks off (a connection dropped, a 5xx) is
  copied again at later looks for up to 15 minutes ("Your result is made. Copying it from your
  GPU"), never made again. Sending a file to the GPU may take as long as its size needs at 128 KB/s
  plus a minute (5 to 30 minutes).
- **A failed run.** The tile shows the sentence, the details line, and up to three buttons (two on
  a narrow tile; the ones that help least go first): **Start your pod**, **Run with your fal.ai
  key** right after it, **Check my GPU** (the Test above, on the saved address), **Open Settings →
  Your GPU** or **Your keys** (**Replace key**), **Add credit on fal.ai** (or Replicate), **Run with
  your Replicate key** when the other key runs the same model (on that key, never back on fal.ai),
  **Pick another model** (it opens the studio's model picker), **Try one size smaller** after a
  run ran out of graphics memory or took too long, **Send a smaller copy** after a file was too big
  for the address (`POST /api/generations/<id>/smaller` makes a smaller copy of the run's biggest
  picture or clip as a new file of the account's, and the run starts again with it), and **Retry**.
  A copy is real work, so an account makes one at a time and the server two at once (429 "Smaller
  copies are busy right now. Try again in a minute."), a clip's encode uses two cores, files that
  are full say so before any work, and a run gets 3 copies an hour (12 for the account). When no
  smaller copy can be made, the message offers **Try one size smaller** (or **Pick another model**).
  A button that starts a run stays pressed until it has, so a second click starts nothing. The
  Library's card shows the same sentence with up to two of them (one in the list), and they act
  there too: **Pick another model** opens the run's studio with the run loaded and its model picker
  open (`?reuse=<id>&pick=1`). The run keeps them in `trouble` (`GET /api/generations/<id>`), next
  to `fix` for **Fix it**.
- **For the owner.** Each wait, heal and failure of an account's run on its own GPU or key writes
  one JSON line to the server's log (`"evt":"own-run"`: the run, the account, the place, provider,
  model, stage, status or network code, the kind of address, the cause, the try and the time
  waited). A run that stops in this server's own words writes one too, with its cause: cut off by a
  restart (`interrupted`, or `interrupted-sending` in the middle of its send), refused as its
  account runs now (`connect-gpu`, `add-key`, `switched-off`…), its keys changed while it waited
  (`keys-changed`), or a step whose earlier step didn't finish (`earlier-step`: the first step after
  the failure only; the steps after it, which stop for the same reason, write none). It never holds
  a prompt, a key, a token, an address or a file's name. A failed run also
  keeps, for the owner only, the cause, stage, code, kind of address and the provider's own words
  (cleaned, 2 KB at most): `ownRunNote(id)` in `src/server/run-events.ts` reads it, and no account
  or visitor answer carries it.

## Hosted runs

By default an account runs only on its own GPU or its own key. An owner who wants accounts to run on this install's
own GPUs too sets `FUOBE_HOSTED_RUNS=1`. It is off unless set, and with it off nothing below changes.

Something must answer for these runs: a billing service (below), whose policy says who may run what, or
`FUOBE_HOSTED_FREE=1`, which makes them free for every account within the install's own limits. With neither, hosted
runs stay closed even when switched on.

With it on:

- An account with no GPU of its own can run in the studios (generations, camera motions, effects, apps) and in the
  tools that plan their runs as ordinary generations (Genjutsu, Shorts, Cinema, Storyboard, the audio tools, palette
  lock and the others above). Every step of a tool's run passes the same checks as a studio run, and the whole run has
  one price. The run goes to this install's GPUs: its workers, when Settings says ComfyUI runs on workers
  ([gpu-workers.md](gpu-workers.md)), or else its own ComfyUI server, only when that is on this machine. An install
  whose ComfyUI runs on the owner's computer doesn't offer hosted runs.
- Where an account's runs go is one order: a place the run names (a one-off "Run on …", Retry, which goes back to
  where the run ran), then what only one place can run (a model this install's GPUs don't take runs on the account's
  own GPU; a cloud-only model on its key), then the account's own pick, then the install's default. With no pick, an
  account whose own GPU is online runs there first, unless the billing service's policy puts this install's GPUs first
  (`prefer: "pool"`).
- **Run on**: for an account with a choice for an item (its GPU, or a key that runs the item's cloud version), the
  composer's price chip opens a list ("Free ▾"): this install's GPUs, Your GPU (with a green dot while it answers; it
  can be picked while it doesn't, and the check before Run then offers **Run on …** for that run), and Your fal.ai or
  Replicate key with its price. A tool page's place chip lists the same rows, and Settings → Your GPU starts with
  **Where your runs go**. A pick applies at once and holds for the account's later runs on every device: it is kept on
  the server (`PUT /api/account/run-on`, `src/server/run-on.ts`), sent in the status to that account only, and read by
  every run and price check that names no place. A pick of the account's GPU sends its runs there without asking,
  even while it doesn't answer; a pick of this install's GPUs or of the key sends open runs here first (the key runs
  what has a cloud version, on the Cloud engine). Forgetting the GPU or removing the key drops a pick of it ("Your runs
  go to … now."), and a deleted account's pick goes with it.
- An account that ran on its own GPU or key before hosted runs went on (and has picked nothing since) sees one note
  above its run button, in a studio or on a tool page: "Runs now go to …, free." with **Keep my GPU as the default**
  (or key) and **OK**. Both keep a pick, so the note shows once for the account, on any device.
- A connected GPU runs what this install's GPUs don't take with the first press ("Free · your GPU"). A key runs such an
  item only when the key is the account's pick; otherwise the press shows "Run with your fal.ai key · ≈ $0.04" (one run,
  its price first) and Connect your GPU. A key is never billed by a press that showed "Free": with the key as the pick,
  the price chip says the key's price first ("≈ $0.04 · your key"), and every key offer on a failed run's tile carries
  its price (one with no price known is not shown).
- A run that failed on the account's own GPU or key offers **Run on …** once, only when this install's GPUs take it
  (on a key: the item's open version), and the account's pick stays. When its key turned the last run down (out of
  credit, not accepted), the composer says so before the next press, with the same **Run on …**.
- A tool open to the owner only (Marketing Studio, Ads Studio, Ad Multiplier, Click to Ad) reads "Coming soon" to
  accounts, with a press to the studio that makes it now ("Make it in the Image studio").
- Visitors read this install's GPUs by one place name: "Runs on our GPUs", "Made on: Our GPUs", "Run on Our GPUs".
  The billing service's policy sets it (`placeName`); without one, Settings → Workers → Name for your GPUs, else
  `FUOBE_PLACE_NAME`, else "Our GPUs". It is never sent while hosted runs are off.
- The studios' engine switch starts on Open source, where open models run free on this install's GPUs. Each account
  keeps its own switch in the browser (a second account on the same browser keeps its own, under a hash of its email,
  never the address; a guest keeps one for the browser), and the owner keeps the browser's one switch. Saving a key
  doesn't move it: Cloud is one pick away, and the note after saving says so. **Run with your fal.ai key** runs that
  one run on the key, and a note's link to a tool's cloud version opens that page on Cloud for that visit: neither
  moves the switch. (With hosted runs off, the browser keeps one switch, starting on Cloud, and saving a key moves it
  there, as before.)
- What this install's GPUs can't run is a label, never a refusal, the same for a guest and an account. The price
  slot says where it runs and its tooltip what to do; Run opens the way there (Connect your GPU, Add your key, or a
  guest's sign-up card for that label), and with the GPU or key already there, the first press runs on it:
  - a model, mode or option that runs only on a person's own GPU or key ("Runs on your own GPU · 48 GB",
    `src/lib/own-setup.ts`), and a run that no worker can take (none holds its files or may run its lane): "Runs on
    your own GPU";
  - extra LoRAs added to a request: "LoRAs run on your own GPU", with "Run without LoRAs";
  - a kind of file the policy keeps off: "This file runs on your own GPU";
  - a choice that needs an NVIDIA RTX card (RTX Video's upscale, frame generation and HDR) when the GPUs' last check
    says their card can't run it, or that their ComfyUI lacks the RTX Video nodes: "Runs on your own RTX GPU";
  - a size bigger than every GPU here makes (each worker's PC ceiling: megapixels, seconds, results at once), said
    before Run: "This size runs on your own GPU", tooltip "Up to 8 megapixels on our GPUs. Pick a smaller size, or
    run it on your own GPU." The run's own size check stays as the last guard;
  - a 3D model no worker finishes (Image to 3D, and Refine detail on its model run there only while a worker's CPU
    slot finishes them, and only when the policy allows 3D, `kinds.model3d`; Any Angle's 3D view runs there like a
    picture): "Runs on your own GPU · 24 GB".

  The answer to such a run is 403 with `code: "connect-gpu"` (or `"add-key"`), the label as `error`, `ownSetup` and
  the `x-fuobe-connect-gpu` and `x-fuobe-own-setup` headers, so the card that opens says what it needs: "This one runs
  on your own GPU" / "It needs a GPU with 48 GB of memory. Connect yours, and this runs there. Everything else runs on
  our GPUs." with **Connect your GPU** and **Pick another model** (never a dead end on a phone). A guest's card says
  "Sign up free, then connect yours in a few steps." instead, never that the run starts once signed in; after sign-up
  the draft is back and that setup opens on the same page, and nothing runs by itself. Only a run past the outputs a
  run here makes is still words (`not-offered`: "Makes up to 4 at a time on our GPUs…"; the tools cut the count).
- Relight and Any Angle run there like the studios (the price check says where, or the label). Canvas board runs and
  the Ads Studio, Ad Multiplier, Click to Ad and Marketing Studio don't run for accounts yet: a board's Run points at
  the studio that makes it ("Make this in the Video studio", on our GPUs), and those tools' place chip says "Coming
  soon" with the studios to use now. A tool no account's own GPU or key runs yet answers "This one isn't open to
  accounts yet. Try the Image, Video or Audio studio, or an app, effect or camera motion."
- A run on this install's GPUs that failed on the person's own files ("A clip or sound in this run couldn't be read.",
  "This run couldn't finish with these files or settings.") offers **Reuse** first (the draft comes back to change),
  and Retry second.
- Tool pages (Cinema, Turnaround, Fly-around, Character Swap Studio, Faceless, Content Factory, Genjutsu, Mixed
  Media, Speech edit, Design a voice) say "Free" for an open run that goes to this install's GPUs, and show that
  run's price and wait where their price check gives it (`toolPoolPrice`). "Free · your GPU" stays for runs that go
  to the person's own GPU (`openFreeWords` in `src/lib/run-place.ts`).
- When a billing service names the models that may run on the studio's GPUs, that applies to every model a run uses,
  not only its main one.
- An account can upload pictures for these runs. Clips and sound go to the workers only when the install allows them
  (`FUOBE_POOL_MEDIA_INPUTS`, [Clips and sound](gpu-workers.md#clips-and-sound)) and the billing service's policy
  does too (`uploads`); with no billing service, `FUOBE_POOL_MEDIA_INPUTS` alone says. Otherwise they need the
  account's own GPU or key.
- A new account goes back to where it was after sign-up, not to "Connect your GPU". Connecting a GPU stays in
  Settings → Your GPU and at `/connect`; the account menu says "Your GPU · Optional".
- Before Run, the line under the toolbar says when the result would be ready ("Ready in about 2 min", "Ready in
  seconds" for light work such as a join or a trim). A run waiting for the studio's GPUs shows its place in line and
  the same wait on its tile ("In line · 3rd · ready in about 2 min"). Once a GPU takes it, its tile says "Working ·
  getting ready" while its model loads (the GPU had another one loaded), then "Working" with its progress.
- A run is taken whatever the line, and Run stays on: while every GPU that could run it is paused, outside its hours,
  silent or built from the catalog before an update, the run waits in line and says "starts when a GPU is free" (or
  "starts in about 3 h" when the first is due back at a known time). An account whose runs go to the studio's GPUs is
  never moved to its own GPU for that, nor while the billing service is quiet; only what those GPUs can't run at all
  goes there. After a long wait (the policy's `limits.offerAfterS`, 20 minutes by default, or a wait with no end
  known; 0 turns this offer off) an account with its own GPU, or a key that runs the item's cloud version, is offered it for that one run
  ("Run it now on your GPU", "Run it now with your fal.ai key · ≈ $0.04"), and its pick of where runs go stays.
- How long a run may wait before a GPU first takes it: the billing service's `limits.giveUpS` when its policy says
  (0: as long as it takes), else what its reserve answer says, else `FUOBE_POOL_WAIT_MIN` minutes (none by default: as long as it takes).
  Past that it fails with one plain sentence, not charged. A later step of a run (a chain's next step) keeps the run's
  place in line and has no wait limit.
- When the billing service's policy says runs wait instead of being refused (`limits.held`: how many may wait behind
  an account's runs at once), a press past a limit is taken all the same: the run and its tile exist at once ("In
  line"), and the run enters the line when its reason clears (`src/server/pool-holds.ts`, released by
  `src/server/pool-release.ts` in the generations runner's turn, in every app process):
  - past the account's runs at once (`limits.activeRuns`): "Starts after your other runs" before Run, "In line · after
    your other runs" on the tile; it enters at the back of the line when one of them ends, so ten fast presses never
    pass another account, and its presses enter in the order they were made;
  - the day's GPU time used up (the service's `startAt` at the next UTC day): "Free runs refresh at 14:20." (or the
    service's display copy, `limitDaily`) before Run, "Free runs refresh at 14:20 · this one starts then" on the
    tile; at the renewal the runs enter at their press-time places, in press order;
  - the billing service doesn't answer within 5 s of the press (or the moderation service doesn't, at a studio's
    press): its tile shows its place as if in line, it reserves (and is checked) under its press's own request id once
    the service answers, and enters at its press-time place. While the service says runs here are paused, the line
    before Run shows its words, and a press waits ("In line · starts when a GPU is free");
  - an hourly limit or free generations that renew (credits on): it starts at that time, at the back of the line.

  Holds are kept in SQLite (`pool_holds`) with a lease per run, so they survive a deploy, a restart and two app
  processes at once. Cancel works on a held run like on any other. A deleted account's holds go with it. Only a press
  past the cap on runs waiting is turned down: "You have 10 runs on the way. Add more when one is done." The owner
  reads the held runs by why they wait (counts only) in Settings → Workers ("Waiting to enter the line: 3 (oldest 12
  min)") and in `GET /api/admin/queue` and `/api/admin/workers` (`held`). Runs waiting longer than 5 minutes for the
  billing or moderation service to answer are said in the server log and, at most once every 5 minutes, in the admin
  log (`runs.waiting`, counts only). With a policy that has no `limits.held` (an older service), every limit
  refuses as before.
- The account's usual limits apply: outputs per run and its space. Its runs at once (4) and per hour (60) count its
  runs on its own GPU or key and its light work (a join, a trim) only: its other runs on this install's GPUs meet the
  billing service's limits instead. (With hosted runs off they count every run, as before.)

Two optional services can go with it:

- a **billing service** ([billing-hook.md](billing-hook.md)): prices runs on this install's GPUs, sets the price aside
  before a run starts, and shows the person a balance. Without one, these runs are closed, or free with
  `FUOBE_HOSTED_FREE=1`.
- a **moderation service** ([moderation-hook.md](moderation-hook.md)): checks a run before it starts and, when it asks
  to, its outputs before they show. Without one, nothing is checked.

The code is `src/server/hosted.ts` (the switch, the place, the line), `src/server/hosted-run.ts` (the run route's side
and the gate), `src/server/account-tool-run.ts` (a tool's run), `src/server/run-stamp.ts` (what every row of a run
carries), `src/server/run-on.ts` (the account's pick of where its runs go) and `src/lib/hosted.ts` (the browser's
side). The tests are `tests/hosted-runs.test.ts`, `tests/run-on.test.ts`, `tests/hosted-surface-labels.test.ts`,
`tests/hosted-tool-runs.test.ts`, `tests/pool-account-runs.test.ts`, `tests/billing-hook.test.ts`,
`tests/billing-release.test.ts` and `tests/moderation-hook.test.ts`.

## Uploads

An account with its own ComfyUI connected, or its own key, can upload files (`POST /api/uploads`,
the file as the request body with its type in `Content-Type` and its name in `X-File-Name`; an
older page's multipart form works up to 26 MB). With neither it answers 403 with
`code: "connect-gpu"`, and a guest gets 401 with the sign-up card. The one exception is a result
rendered in the page (sent with `x-fuobe-kinetic: 1`: a Kinetic Motion clip and its poster, a colour
grade, a Relight blend): any account may upload its MP4 or WebM clip or its PNG picture, within the
same space, size and upload limits below. Any other type
sent that way answers 403 `connect-gpu`, and a model run still needs the account's own GPU or key.

| What | Types | Largest |
|---|---|---|
| Pictures | PNG, JPEG, WebP | 25 MB and 40 megapixels |
| Sound | MP3, WAV, OGG, FLAC, M4A, WebM | 50 MB |
| Clips | MP4, MOV, WebM, MKV, AVI | 95 MB (ComfyUI takes up to 100 MB unless started with more) |

- The type is read from the file's first bytes. A file that isn't one of these answers 415.
- `Content-Length` is required (411), and a file over its size answers 413 before it is read.
- An account keeps up to 1 GB of uploads and 5 GB of files in all (uploads and results), from the
  day it signs up, existing accounts too. Past that, uploads and runs answer 413: delete some runs to make room.
- All accounts together keep at most a quarter of the data disk (`FUOBE_ACCOUNTS_DISK_GB` sets
  it), and the disk always keeps its free floor (`FUOBE_ACCOUNT_DISK_FREE_GB`). Past either,
  account uploads and runs answer 503 "short of space"; the owner's work is not affected.
- Up to 60 uploads an hour, 300 a day and 2 at once (429 with `Retry-After`). An upload sent as a
  form (older pages, held in memory) also waits for a place among 8 from every account together.
  An upload ends with 408 when nothing arrives for a minute, or when it takes over 30 minutes.
  One address (one network) makes at most 20 accounts a day.
- **How long files stay.** Uploads are removed after 14 days, even when a run still uses them.
  Runs and their results are removed after 30 days. Everything goes at once when the account is
  deleted.

`GET /api/auth/me` (open to everyone) says who is looking: `{ signedIn, owner, publicSignup,
account? }`.

The rules are in `src/lib/guest-access.ts` (which paths guests and accounts may use) and
`src/proxy.ts` (where they are applied). Your GPU is `src/server/account-gpu.ts`, `onOwnGpu` in
`src/server/providers/comfyui.ts` and `accountRun` in `src/server/generations.ts`; what an account's
work may read is `src/server/tenant.ts`. Your keys are `src/server/account-keys.ts` (storage),
`src/server/secret-box.ts` (encryption), `src/server/provider-keys.ts` (`cloudKey`, the one place a
fal.ai or Replicate key is read) and `src/app/api/account/keys`; their tests are the
`tests/account-keys*.test.ts` files, `tests/secret-box.test.ts`, `tests/byo-keys-static.test.ts` and
`tests/e2e/byo-keys.mjs` (against stand-in providers). Connected accounts (a key's balance and account) are
`src/server/provider-account-info.ts` and `src/app/api/key-info`, tested in `tests/key-info.test.ts` and
`tests/key-info-ui.test.ts`. Uploads are `src/app/api/uploads/route.ts` (which makes the
proxy's checks itself, `src/server/direct-gate.ts`), the limits are in `src/server/account-files.ts`
and the clean-up in `src/server/account-sweep.ts`. The owner's view of what accounts make is
`src/server/account-admin.ts`. The tests are in `tests/public-signup.test.ts`,
`tests/accounts-admin.test.ts`, `tests/account-runs-admin.test.ts`, `tests/account-gpu.test.ts` and
the `tests/account-*.test.ts` files.
