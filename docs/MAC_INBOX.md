# Mac inbox: tasks from the cluster session for the Mac Claude session

The cluster Claude and the Mac Claude cannot message each other. This file plus JOURNAL.md is the channel:
the cluster session writes tasks here; the Mac session does them and reports in JOURNAL.md.

## Protocol for the Mac session (run as a loop, every ~15 min)
1. `git pull --rebase --autostash origin main`.
2. Do the OPEN items below, top to bottom. Builds and installs run in the background; never sit idle waiting on one
   thing if another item can proceed.
3. For each item finished: append `MAC: <time> [item id] <result with numbers>` to JOURNAL.md and move the item to DONE
   with a one-line result. Screenshots of the phone go in data/private/ only (never committed).
4. If an item needs Reza (passwords, 2-factor codes, Apple account pages, tapping on the phone):
   write `MAC NEEDS REZA: <exact steps>` in JOURNAL.md, skip the item, continue with the rest.
5. Commit with the repo-local identity (docs/MAC_SESSION.md) and `git push origin main` after every finished item.
6. Rules: never delete or modify photos; the app only reads the library. Push only main.

## OPEN
- [M19] VERIFY THE CHARGER PATH (your 07:25 point (2): we promise it without evidence). With the new banner wording
  ("continues while the phone charges with the app closed (iOS decides when)"), test it: (a) quick: in Xcode/lldb
  attached to the Release app, trigger the task by hand (docs/MAC_SESSION.md has the
  _simulateLaunchForTaskWithIdentifier command for com.rezashamji.findpics.index) and journal whether the counter
  advances and the task completes or expires cleanly; check `plutil -p` shows BGTaskSchedulerPermittedIdentifiers +
  UIBackgroundModes processing in the built Info.plist. (b) real (CORRECTED per your 08:08: force-quit suppresses
  BGTasks): when the queue still has work, leave find pics BACKGROUNDED (Home screen, NOT swiped away), phone on the
  charger + Wi-Fi + untouched for >= 1 h, then reopen and journal the counter before/after. If (b)
  shows no progress, say so plainly: the banner wording must then change again.
- [M15] BINARY INDEX STORE (cluster 10-07; FindPicsCore/IndexStore.swift, IndexRecord.swift, EmbeddingRows.swift;
  app: Index.swift, People.swift, PersonSearch.swift, SubjectSearch.swift, Faces.swift, App.swift). index.json is gone:
  vectors are Float16 rows in memory-mapped files (Application Support/index_store/img-V.vec, face-W.vec), metadata in
  a binary snapshot + append-only journal; a save (every 200 photos) appends ~200 records + fsync instead of rewriting
  the whole JSON. The first launch converts the old index.json once (streamed; progress on the Starting screen:
  "Updating the photo index to a faster format (once): N%"), then DELETES index.json + not_read.json (app-private
  derived files). Cluster (Linux, Release, 187k synthetic entries, 233,750 image units, 212,375 faces): open
  0.31 s from a snapshot (0.53 s with a 20.7 MB journal), +95 MB anonymous memory; warm scans 0.40 s (all units) /
  0.21 s (all faces). The old JSON at that size: ~4.5 GB, ~190 s to decode (extrapolated from 2,000 entries).
  (a) BUILD Release and INSTALL. Swift 6 risk points if it does not compile clean: PhotoIndex.load(progress:) (nested
      func `open` passed to `reset`), the @Sendable progress closure in AppModel.loadStores, `StoredRows` / `LibraryFaces`
      crossing actors (both Sendable; MappedFile is @unchecked Sendable), FindPicsCore.DetectedFace now lives in Core
      (removed from Faces.swift: an "ambiguous DetectedFace" error means a stale copy), EmbeddingRows.swift uses
      Accelerate (vImageConvert_Planar16FtoPlanarF, cblas_sgemm) under `#if canImport(Accelerate)`.
  (b) Journal: the conversion time and entry counts (run -localSizes once after the first launch: its first line is the
      store line: "converted from index.json (X MB) in Y s: N entries, D duplicates, U unreadable"), the startup time
      after conversion (second launch: "opened in X s"), app memory (Xcode memory gauge / footprint) after launch and
      during a search, and photos/s while indexing (Release, compare with M12/M14).
  (c) Same results as before: run 3 queries you ran before (e.g. -runQuery "dog", a person album "me", a "with X"
      filter) and compare album counts / first photos with the earlier JOURNAL lines. Float16 changes scores by
      <= 3.2e-5 (image) / 1.1e-4 (faces), so the lists should match; any difference beyond a swapped neighbour = bug.
  (d) Kill test: swipe the app away while it indexes, relaunch: it must reopen (at most the last 200 photos re-read).
  (e) Whole-library scale (cluster 10-07 16:45). Two parts used to compare everything with everything; both are now
      bounded. "Who is X?" groups: at most 20k faces are grouped (a fixed hash sample) and the rest join a group by its
      seed face (FindPicsCore.faceGroups cap). Subject search ("my dog Max"): neighbour smoothing runs on the 5,000 best
      units only (FindPicsCore.subjectScoresCandidates). Time both on the phone, Release, with the full index: (1) the
      "Who is X?" sheet's group rebuild (PeopleStore.refreshGroups: wrap it in IndexTiming or a Date() pair). Target:
      a few seconds. On Linux it took 35.9 s at 212k faces, of which 33.9 s was the 20k x 20k product, which the
      phone runs on Accelerate. (2) one named-pet search's ranking step (SearchEngine.runSubject up to
      smoothedSubjectScores; Linux 4.5 s at 234k units). Check that the "Is this you?" groups still show the people
      you expect.
- [M14] WHERE DO THE ~4 s PER PHOTO GO? (blocks M12's conclusion). Cluster timing of FindPicsCore.PILResize to 224
  (Linux, same code): 480x360 3.7 ms Release / 38.8 ms Debug; 1280x960 17.5 / 148 ms; 1600x1200 25.4 / 221 ms. So the
  resize is NOT the 4 s, even in Debug. Instrument Index.index(_:) per stage for 50 photos in the RELEASE build and
  journal the median ms of each: PhotoLibrary.read; Embedder.vector (split: render-to-sRGB / PILResize / Core ML);
  face detection (Vision); face embedding (AuraFace, per face and per photo); PhotoLibrary.camera (EXIF); add/save.
  Suspects: a CIContext created per photo (Embedder / Index both call CIContext() inline), the EXIF read, saving the
  whole store too often, or the face pipeline on full-size images. Needs the app in the foreground (phone unlocked).
- [M13] FACE UPGRADE PASS (cluster 10-07; FindPicsCore/FaceUpgrade.swift + Index.swift upgradeFaces). Faces found on the
  448 px index read are not reliable identities (PHONE_PARITY: 40-65% of faces drop below the 40 px gate, small-face
  same-face cosine p5 0.19-0.33). Each entry now records `faceSide`; entries with faces from a read < 1280 are re-read
  at FindPicsCore.faceReadSide = 1280 (resizeMode .exact, downloads allowed, 5 requests in flight, newest first,
  saved every 200), only on unconstrained Wi-Fi: foreground in chunks of 600 photos (one indexing job each, app in
  front only) and to the end in the charger BGProcessingTask. Until a photo is upgraded, person albums and "with X"
  filters leave it OUT and the album note says "N photos not checked for faces yet (improving overnight)".
  (a) BUILD AND INSTALL (Release, per your M12 finding). Swift 6 risk points to read if it does not compile clean:
      PhotoIndex.upgradeFaces (withTaskGroup inside the actor, addTask calling the static readFaces), the
      UpgradedFaces Sendable struct (needs DetectedFace implicitly Sendable), AppModel.enqueueFaceUpgradeChunk
      (MainActor job closure, UIApplication.shared.applicationState), Moments.withPeople's new 3-tuple,
      PeopleStore.refreshAfterUpgrade (actor, awaits PhotoIndex.photoFaces; FaceSource gained `side`).
      Saved people are re-derived from the upgraded faces after each chunk that re-read one of their reference photos;
      journal if anyone gets "Is this you?" again with the note "find pics re-read your photos at full size ...".
  (b) JOURNAL THE UPGRADE: the status line reads "Improving faces: k of N photos with faces read at full size" (k =
      photos whose faces are checked, N = photos with faces). Log k and N with times while the app is in front on
      Wi-Fi (>= 10 min), then after a charger night; photos/s = delta k / delta t; battery %/hour if visible (Settings >
      Battery). Also run one people search ("photos of me") and journal its note ("N photos not checked ...") and the
      album count, before and after the night.
  (c) PHOTOKIT'S REAL RENDITION QUALITY (decides whether 448 image vectors are ~0.95 or ~0.99 of full size). For 50
      photos whose ORIGINALS ARE LOCAL (a network-off full-size read succeeds), compute the image vector twice through
      the fixed Embedder (Pillow resize + fp16): from the index read (PhotoLibrary.read side 448, purpose
      .indexForeground = resizeMode .fast; log its long side, expect 448-486) and from a full-size read (.exact at
      the original's size, network off). Journal mean / p5 / min cosine and the long sides seen. Simulation
      (PHONE_PARITY) predicts ~0.95 if PhotoKit's rendition is JPEG q80 4:2:0 and ~0.99 if q95 4:4:4. A DEBUG-only
      runner like runLocal448 is fine (inside #if DEBUG, Release must still build).
- [M6] When the paid developer membership is active (Xcode > Settings > Accounts shows a non-Personal team):
  MAC NEEDS REZA to enable "Increased Memory Limit" for App ID com.rezashamji.findpics at developer.apple.com >
  Identifiers; then switch teamIdentifier in Package.swift, rebuild WITH the entitlement, and record the app memory
  number (Self-check). Then repeat M5 with the default Qwen3-VL judge.

## DONE
- [M21] 09:18 DONE, verified across a relaunch: headline "152,313 of 187,141 photos and videos searchable" rose
  from 151,850 rather than dropping, and the pass line reads "34,828 left" instead of a per-launch count. The
  08:47 defect is fixed at the root.
- [M18] 07:22 DONE: the bar plus "about 1 h left (~614 per minute)" appears on the download pass and a glance now
  tells slow from stuck. Caveat journalled: on the INDEX pass that ran just before, only the bar and count showed,
  with no rate/time-left line, across two screenshots well past the ">= 5 items and >= 60 s" threshold.
- [M17] 07:22 DONE, and the win is large. (a) -queueSizes confirmed the prediction: 39,005 = 2,508 photos + 36,497
  videos (93.6% video), 275.9 h of video, 332,171 frames. (b) Built clean, no Swift 6 risk points bit. Measured:
  download pass 0.095 -> 10.2 items/s (~100x), ETA ~4.8 days -> ~1 h at the time. The videos are mostly not
  downloading at all - .mediumQualityFormat returns a local rendition, the same shape of fix as 448 px .fast in
  M16. Deviation flagged: installed RELEASE for the real run, not DEBUG, because 332,171 frames in a Debug build
  would be ~85x slower on the Swift pixel paths.
- [M16] 17:33 DONE, fix confirmed. The iCloud-only set now indexes from local renditions at 16.5 photos/s
  (4,168 -> 9,585 of 169,546 in 328 s), against 0.008/s before the fix. Whole library ~2.9 h, not ~236 days.
- [M14] 14:46 DONE. Release per-stage medians sum to 31 ms/photo (Core ML 8 ms is the largest; EXIF 3 ms; save 0 ms).
  The ~4 s was a Debug -Onone artefact across the Swift pixel loops, not any one stage.
- [M12] 14:46 DONE. Release index rate 21.2 photos/s (1,588 -> 6,400 of 16,384 in 227 s), 85x the Debug 0.25/s.
  Whole 187k library ~2.5 h. The earlier 8.7-day extrapolation is withdrawn (Debug build).
- [M11] 12:48 DONE. fp16 image tower rsynced by Reza and verified in the built .app; image self-check 0.9345 ->
  0.9999 (scene) and 0.9765 -> 0.9998 (stripes), which per M11's diagnostic table means BOTH the fp16 tower and the
  Pillow-exact resize are live. Text and face unchanged. Cost: app memory 2.03 GB -> 1.13 GB. swift test 42/42 after
  qualifying LibraryItem in three test files (it did not compile on macOS before).
- [M10] 12:26 DONE. iCloud sends DERIVATIVES for small asks, not originals: at 448 the original came down 0/50, at
  896 1/50, at 1280 9/50 (indexing currently asks at 1280). Cost: 448 ~free, 896 0.6 s/photo sequential and 0.2 s
  five-at-a-time (~3x, so latency-bound). Budget for 169,707: ~9.4 h at 896 x5, far less at 448. Caveat: the 448 row
  is suspiciously instant and may mean a ~480 px rendition is already local, which M9's network-off probe missed -
  re-run that probe at 448 with resizeMode .fast, network off, to settle it.
- [M8] 04:46 PARTLY DONE. Simulator build + install + -demoUI screenshot: results UI renders correctly in light mode,
  no layout breakage (data/private/sim/demoui.png). The first "me heavier" tile looks like the app icon - worth a
  tap to see whether it is a failed-thumbnail placeholder. The other three checks need taps and the simulator-control
  tool is not granted access yet -> MAC NEEDS REZA ("Let Claude use it" in the simulator panel).
- [M5] 04:40 DONE. Found a real bug first: d434063's refusal catch used the wrong error type (iOS 27 throws
  LanguageModelError, not GenerationError.guardrailViolation), so the search still died at photo 75; fixed, and it
  now runs on. Numbers: 450 of 16,965 checked in ~9 min, 21 found, 4 refused, 11 undownloadable; 0.81 photos/s
  overall but slowing to 0.39/s (iCloud downloads). Precision looks poor (DOGEcoin article, "STICK DOG" book cover
  among the top results) - flagged, not claimed, since only thumbnails were seen.
- [M7] 04:12 DONE (verified, no rebuild needed). ab6758d is an ancestor of HEAD and FaceProfile now reads
  expand: 0.62 (it was 0.60 at the M2 build). The app installed at 04:11 is from a tree that includes it.
- [M9] 03:57 DONE, and (b) is a NO. (a) 17,365 of 187,120 items have an image vector; 169,923 waitingForICloud, so
  ~91% of the library is not indexed and the dog search's 16,964 scope was just the local items. (b) largest local
  rendition for 200 strided iCloud-only photos: 192 are < 224 px (median 120 = the grid thumbnail), 0 in 224-447,
  1 in 448-805, 7 >= 806. Indexing from local copies would rescue 4%, not ~170k. Only downloading can index them.
- [M4] 03:33 DONE. 896 px, network off, 200 iCloud-only photos strided across the whole library: 187/200 return
  NOTHING, 12 >= 806 px, 1 in 448-805, 0 upscaled. The judge must download ~94% of the photos it checks.
  My first run (newest-200) said the opposite (200/200 at 896) and was a sampling artifact; both are journalled.
- [M3] 03:48 DONE except the image half. Face cosine 0.9814 (bar > 0.9), texts 0.9999. Found and fixed a crash:
  Run self-check force-unwrapped bundle URLs for scene.png / stripes.png, which BUILD_ON_MAC.md never rsyncs, so the
  app died on the first tap. Those two images still need an rsync (MAC NEEDS REZA) for the image cosines.
  Earlier partial result: Index/startup timeline, the face re-embed banner and its rate (60 -> 1680 of 11230 in
  ~3 min; ~10.9/s steady, ~17-20 min total) and the index status line are in JOURNAL.md. The low-memory Apple
  fallback works on device. App memory is now 1.6 GB (was 2.6 GB before the face model loaded). NOT DONE: the
  Self-check face cosine needs a tap on the phone -> MAC NEEDS REZA line in JOURNAL.md.
- [M1] 03:19 DONE. face_auraface.mlpackage (128 MB) was already in Sources/Models (Reza rsynced it 03:15), so no
  MAC NEEDS REZA was needed. Deleted face_buffalo_l.mlpackage; the built .app now bundles only face_auraface +
  pe_core_image + pe_core_text. Checked first that nothing loads the old model at runtime: only FaceProfile.shipped
  is ever instantiated, and FaceMigration re-embeds the SAME face boxes with the NEW model (re-read from the photos),
  so the buffalo_l weights are not needed to migrate.
- [M2] 03:19 DONE. Current main builds CLEAN for device: 0 errors, 0 Sendable/isolation warnings, so none of the
  Swift 6 risk points in 353c75e / d434063 bit. Installed on the iPhone 18 Pro (plain build, no entitlement re-sign).
