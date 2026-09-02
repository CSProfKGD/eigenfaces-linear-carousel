# Eigenfaces Demo — Implementation Context

## Experience contract

The page is an interaction-led educational working surface. It should let a visitor understand that a face is represented as an average plus weighted directions of variation, then immediately test that idea by changing a small number of weights.

### Desktop layout

- Use one continuous black stage aligned to a shared content grid.
- Place the hero at the upper left:
  - Title: `Eigenfaces`
  - Subtitle: `Face It: It’s Just Linear Algebra`
- Center the square reconstructed-face figure beneath the complete hero title and subtitle, with clear vertical separation.
- Put `Reconstruction` and the unboxed cyan `Reset weights` action on opposite sides of the figure topline. Beneath the image, show only `Variance retained` and `Dimensions`; do not show a projected-face-count metric, and keep the dimensions disclosure clear of reset.
- Place a full-width looping linear carousel below the reconstruction. Reading order is `Mean`, `PC 01`, `PC 02`, …, `PC 24`.
- Start with `Mean` centered. Show approximately seven slides at wide desktop widths.
- The reconstruction remains visually dominant. The centered slide is largest; adjacent slides progressively recede and fade.
- The mean slide uses the same visual framing as the eigenface slides but has no slider.

### Responsive layout

- At narrow widths, order the content as hero, reconstruction, then carousel.
- Show approximately five slides on tablets and three with edge peeks on phones.
- Never introduce horizontal page scrolling.
- A revealed slider must stay inside its centered slide and remain usable without obscuring the component label or weight value.

### Component interaction

- Use the installed shadcn Carousel backed by Embla with center alignment, looping, and one slide per snap.
- Continuously interpolate slide scale, opacity, and brightness from distance to the active snap; use compositor transforms so the strip never reflows.
- Never auto-advance the carousel. Movement occurs only through direct user input.
- Disable nonessential scale transitions under `prefers-reduced-motion`.
- Support pointer drag, touch swipe, click/tap-to-center, and Left/Right arrow navigation without a visible previous/play-pause/next control row. Faster flicks may carry across additional snaps, but motion must settle on an exactly centered slide.
- Only the centered PC may reveal a weight control. On pointer devices, hovering the bottom half reveals it while the upper half remains inspection-only; keyboard focus still reveals it from any entry point, and tapping the centered slide reveals it on touch.
- Use a restrained 6px corner radius on the reconstruction and face tiles.
- Reveal a translucent control surface over the lower half of an active tile. Preserve enough of the eigenface above and around it to connect the control to the image.
- Use a native range input. Pointer and touch changes update the reconstruction immediately.
- Once the weight surface is revealed, pointer and touch gestures that begin anywhere inside it belong to the slider and must not initiate an Embla drag.
- Display weights in standard-deviation units for human readability: `z_i = w_i / sqrt(lambda_i)`. The stored calculation continues to use raw PCA weights.
- Each slider spans `z_i,baseline - 3` through `z_i,baseline + 3`, which is equivalent to raw weight bounds `w_i,baseline ± 3 sqrt(lambda_i)`.
- The reset control restores all 24 exposed raw weights to their baseline values in one state update.
- A PC above the current dimensions value remains browseable but its weight control is disabled and labelled outside the current prefix. Preserve its adjusted value so it becomes effective again when the prefix grows.
- The reconstruction dimensions value reveals a minimal slider on hover, keyboard focus, or tap. It spans 1–1000 in integer steps, defaults to 512, and updates the displayed prefix and actual cumulative explained variance together.
- Give the dimensions disclosure enough vertical clearance for its thumb and focus ring; its horizontal reveal mask must not clip the circular control above or below.

## Dataset selection and provenance

Use the Flickr-Faces-HQ dataset (FFHQ) published by NVIDIA. FFHQ contains aligned face images and is appropriate here because its contemporary, varied portraits are a closer domain match for the supplied input than older laboratory datasets.

This project uses FFHQ only for a non-commercial educational visualization of PCA. It must not be described or extended as face recognition, identity matching, biometric verification, or demographic analysis.

### Required attribution and restrictions

- Cite Tero Karras, Samuli Laine, and Timo Aila, *A Style-Based Generator Architecture for Generative Adversarial Networks*.
- Link to the official dataset repository: <https://github.com/NVlabs/ffhq-dataset>.
- State that the source images were automatically aligned and cropped and that this project converts a deterministic subset to grayscale, resizes it, and derives PCA artifacts.
- Preserve FFHQ's CC BY-NC-SA 4.0 dataset terms and the original per-image license metadata obligations.
- Treat all derived mean, eigenface, and reconstruction artifacts as non-commercial/share-alike material unless a later legal review establishes otherwise.
- Retain attribution and machine-readable provenance for the selected image identifiers and licenses in the project artifacts. The presentation surface intentionally omits a visible attribution footer.

Do not commit the downloaded corpus or the 255 MB FFHQ metadata file. The offline pipeline may cache them in an ignored working directory.

## Deterministic training subset

- Use only FFHQ records whose official metadata category is `training`.
- Select exactly 5,000 unique records with a fixed pseudorandom seed of `20260902` from the sorted training record identifiers. Sampling is without replacement.
- Persist the seed, sorted selected identifiers, source thumbnail checksums, original authors, source URLs, and image licenses in a generated provenance manifest.
- Use the official aligned 128 × 128 thumbnail pixels. Do not realign individual FFHQ thumbnails.
- Decode to sRGB, compute grayscale luminance as `Y = 0.2126 R + 0.7152 G + 0.0722 B`, and scale values to floating point `[0, 1]`.
- Flatten every image in row-major order to a 16,384-element vector. Preserve one consistent row-major convention through training, export, tests, and browser rendering.

The deterministic sample rule provides reproducibility; it does not claim demographic balance. Do not describe the sample or resulting eigenspace as unbiased or representative of humanity.

## Supplied portrait preprocessing

The source portrait is `/Users/kosta/Downloads/IMG_6763 2.heic`. It is a 914 × 1003 Display P3 HEIC photograph with a near-frontal, smiling subject and a real-world background.

- Perform preprocessing offline; never bundle or request the raw HEIC from the browser.
- Decode the embedded orientation and convert the image to sRGB before landmark detection or resampling.
- Detect a single primary face and stable eye and mouth landmarks.
- Apply the same eye/mouth-oriented square alignment geometry used by FFHQ's published alignment procedure: center and rotate from the eye midpoint, eye-to-eye vector, and eye-to-mouth vector; include the full forehead, jaw, and lateral face boundary while excluding as much room and clothing as the FFHQ crop permits.
- If automated landmarks are ambiguous, inspect the aligned result and record any manual landmark correction in the provenance manifest. Do not silently substitute a different photograph.
- Resample the aligned square to 128 × 128 with a high-quality Lanczos filter, convert it with the same sRGB luminance equation used for training, and scale to `[0, 1]`.
- Validate that the aligned face is upright, both eyes are visible, the face scale matches representative FFHQ thumbnails, and the output contains exactly 16,384 finite samples.
- Store the processed grayscale input only if the interface needs a comparison or development fixture. The required first-version interface displays the reconstruction rather than the source image.

Because the portrait includes a broad smile and stronger expression than many training examples, some residual blur or expression loss is an honest property of a linear eigenspace. Do not conceal that limitation with generative enhancement, identity-aware retouching, or post-reconstruction sharpening.

## PCA pipeline

Let `X` be the `5000 × 16384` training matrix, with one grayscale image per row.

1. Compute the per-pixel mean `mu` and center the data: `Xc = X - mu`.
2. Fit exactly the first 1000 principal components with a deterministic randomized SVD implementation configured with the same seed, `20260902`.
3. Sort components by descending eigenvalue. Preserve the fitted ordering in every exported artifact.
4. Canonicalize each eigenvector's otherwise arbitrary sign: locate the element with greatest absolute magnitude and multiply the vector by `-1` when that element is negative. Apply the same sign change to all corresponding projected weights.
5. Calculate and export the actual cumulative explained-variance ratio for every prefix `k = 1…1000`, plus checkpoints 128, 256, 512, and 1000.
6. Project the processed portrait once into all 1000 components: `w = U_1000 @ (x - mu)`.
7. Precompute each prefix reconstruction `r_k = mu + U_k.T @ w_k`; the default baseline is `r_512`.

Here, `U_1000` has shape `1000 × 16384`, `w` has length 1000, and every prefix reconstruction has length 16,384. Keep the complete Float32 basis and coefficients in the offline cache. Clamp only the compact browser display prefixes while converting them to luminance.

The 24 public weight controls correspond to components 1–24 by explained variance. Components 25 through the selected `k` remain fixed at their projected portrait weights; components above `k` are omitted.

## Browser reconstruction contract

The browser does not refit PCA. Export compact cached prefix reconstructions for `k = 1…1000`, the exact cumulative explained-variance curve, the Float32 default baseline, and the 24 eigenvectors needed for live weight deltas.

For adjustable raw weights `w'_1 … w'_24`, render:

`r_display(k) = clamp(r_k + sum((w'_i - w_i) * u_i for i = 1..min(24,k)), 0, 1)`

This formula is the central invariant. It ensures that:

- untouched weight sliders reproduce the selected prefix, with `k=512` using the exact Float32 baseline;
- hidden components through `k` remain present and unchanged;
- moving one slider changes only its eigenface direction; and
- reset returns exactly to the original projection.

Implement this calculation in a framework-independent TypeScript module using typed arrays. Render the 128 × 128 luminance buffer to a canvas or equivalent pixel surface without network calls. A slider input should schedule at most one paint per animation frame while always using the newest state.

## Generated asset contract

The offline pipeline should produce a compact, versioned manifest and binary numeric payloads rather than large decimal JSON arrays.

### Manifest fields

The exact serialization may follow the generated site scaffold, but the logical manifest must contain:

- schema version;
- dataset name and official source URL;
- selection seed and selected-record provenance-manifest path;
- image width, height, grayscale transform, and flattening order;
- training sample count;
- default dimensions 512, maximum dimensions 1000, and the actual cumulative explained variance for every prefix;
- compact cached prefix-reconstruction payload path, encoding, and checksum;
- baseline reconstruction payload path and checksum;
- mean-face display asset path and checksum;
- component records 1–24, each with eigenvalue, baseline raw weight, baseline standardized weight, raw eigenvector payload path, display-thumbnail path, and checksums;
- portrait preprocessing metadata sufficient to reproduce its alignment without embedding the original image;
- pipeline version and deterministic seed.

### Numeric payloads

- Store the baseline reconstruction and 24 raw eigenvectors as little-endian Float32 values.
- Validate payload lengths before use: the baseline and every eigenvector must contain exactly 16,384 finite values.
- Generate the average-face display image from `clamp(mu, 0, 1)`.
- Generate each eigenface thumbnail with a symmetric per-component mapping around mid-gray:
  `thumbnail_i = 0.5 + 0.5 * u_i / max(abs(u_i))`.
- Do not use independent positive and negative min/max scaling, because that would obscure the zero point.
- Preserve binary numerical eigenvectors separately from their display-normalized thumbnails.

## State model

- Immutable loaded state: manifest, 1000 cached prefix reconstructions, default baseline, eigenvectors 1–24, eigenvalues, baseline weights, and cumulative explained variance.
- Mutable UI state: selected dimensions (default 512), 24 adjusted raw weights, the selected carousel snap, and currently revealed control.
- Derived state: selected prefix, standardized display values, actual retained variance, and current reconstructed luminance buffer.
- Do not duplicate reconstruction state across the stage and component carousel. Both consume the same canonical values.
- Do not persist adjusted face weights across sessions unless a later product requirement explicitly requests it.

## Visual language

- Background: continuous near-black presentation stage.
- Type: system Apple stack, near-white primary text, cool muted secondary labels, tabular numeric values.
- Cyan: focus, live slider tracks, and active component state only.
- Warm gold: a single restrained emphasis associated with the reconstruction or reset-to-baseline state.
- Images: crisp square grayscale surfaces with hairline framing and no decorative colorization.
- Captions: sample luminance beneath the left label and right percentage independently, choose light or dark text for contrast, and retain an opposing shadow for mixed-tone imagery. Label the average-face card only as `Mean`.
- Motion: short opacity/transform transitions for disclosure and focus; no entrance animation and no easing on direct slider movement.
- Keep the title large and confident but subordinate the hero's footprint to the working surface.

## Accessibility requirements

- Use a true `h1` for the title and meaningful figure captions for the reconstruction, mean, and components.
- Use native `input type="range"` controls with programmatic labels such as `Adjust principal component 1 weight`.
- Announce numeric values without causing a live-region utterance for every pointer movement.
- Support arrow keys, Home, End, Page Up, and Page Down through native range behavior.
- Make slider controls discoverable by focus without requiring hover.
- On touch, tapping a different component dismisses the prior overlay and reveals the new one.
- Provide visible focus rings, sufficient contrast, and targets of at least 44 CSS pixels where touch interaction is expected.
- Under `prefers-reduced-motion: reduce`, remove slide scaling and reduce disclosure transitions to effectively instantaneous state changes.

## Tests and acceptance criteria

### Offline pipeline

- The selected FFHQ IDs are identical across clean runs with seed `20260902`.
- The training tensor is `5000 × 16384`, finite, row-major, and within `[0, 1]`.
- The processed portrait is 128 × 128, finite, and uses the same grayscale transform and row-major convention.
- Eigenvalues are non-increasing and eigenvectors are orthonormal within an explicit floating-point tolerance.
- Component signs follow the canonical greatest-absolute-element rule.
- The fit contains 1000 variance-ordered components and the manifest contains 1000 monotonically nondecreasing cumulative explained-variance values.
- Recomputing the default baseline from `mu`, `U_512`, and `w_512` agrees with the exported baseline within Float32 tolerance.

### Browser math

- Initial dimensions are 512 and baseline weights render the exported 512-component baseline exactly within Float32 tolerance.
- The dimensions slider reaches both 1 and 1000; decreasing `k` removes higher component contributions and increasing `k` restores them from the cached projections.
- Displayed retained variance is read directly from the actual cumulative explained-variance entry for the selected `k` and increases monotonically.
- Moving only component `i` by delta `d` changes the unclamped buffer by exactly `d * u_i` within tolerance.
- Hidden components 25 through the selected `k` remain represented and never change during weight interaction.
- Reset restores all 24 original weights and the exact baseline buffer.
- Display conversion clamps values below 0 and above 1 without mutating the underlying baseline or component arrays.
- Corrupt, missing, non-finite, or incorrectly sized assets produce an accessible error state rather than a blank or distorted canvas.

### Interface

- The desktop first viewport contains the dominant centered reconstruction, top-left hero, and full-width component carousel.
- Mean is first, initially centered, and noninteractive; PC 01–24 follow in correct variance order.
- Hover, keyboard focus, and touch can each reveal and operate every centered component slider.
- Slide scaling does not cause layout shift or clipping of focus indicators.
- The carousel loops only through direct swipe, drag, click-to-center, and keyboard navigation; it never advances on a timer.
- Reset is keyboard and touch accessible and visibly returns every readout to its baseline.
- Mobile layouts preserve content order and introduce no horizontal scrolling.
- Reduced-motion mode removes nonessential scaling and animation.
- The supplied portrait and its derivatives are absent from social-preview metadata and imagery.

### Final verification

Run the eventual repository's tests, lint checks, and production build. Check desktop, tablet, and mobile widths; keyboard-only navigation; touch interaction; reduced motion; and 200% zoom. Compare the rendered page with the sibling Dolly Zoom demo for visual hierarchy, alignment, typography, spacing, palette, and restraint while retaining the eigenfaces-specific layout defined here.
