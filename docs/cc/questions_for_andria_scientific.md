# Open questions for Andria: scientific and technical

Maintained by Chris with Claude Code; kept current as work proceeds (see
AGENTS.md). Simple and logistical questions are in
`questions_for_andria_general.md`. Each entry says what the code does now,
why it matters, what the options are, and what we need from you. Line
numbers refer to the code as received (branches `main` / `legacy`).
Updated 2026-09-18.

## A. Uncertainty

### A1. The 200 land-cover draws are averaged away before use
**What the code does.** `veg_posts_interp_ice.RDS` holds 200 posterior
draws (`iter`) of each cover fraction for every cell and time slice.
Script 1 (`1_veg_lct_prep.R`, lines 218-222) takes the mean over the 200
draws and passes a single cover value per cell and slice to everything
downstream. From that point on, no land-cover uncertainty exists in the
pipeline: the calibration is fitted to the mean modern field and the
Holocene hindcasts use the mean paleo field.
**Why it matters.** In the meeting you described the intended approach
as "take multiple samples from the posterior and summarise mean and
sd". Today that summary happens only for land cover, and only implicitly,
because the mean is used and the spread is discarded. The albedo and
forcing results therefore carry none of the uncertainty in the
reconstructions.
**Options.** (i) Keep using the mean, and say in the paper that
land-cover uncertainty is not propagated. (ii) Carry a subset of the
draws (for example 20 to 50 of the 200) through prediction: fit the
calibration once on the mean modern field, then run the hindcast once per
draw and pool the results, so the albedo intervals include land-cover
uncertainty. (iii) Both calibration and prediction per draw, which
multiplies the fitting time by the number of draws and is probably out of
reach.
**What we need from you.** Is (i) acceptable for this paper, or should we
implement (ii)? If (ii), how many draws, and should the calibration also
see the spread?

### A2. What the albedo "posterior samples" actually are
**What the code does.** Script 6 (`6_prediction_model.R`, line 49) calls
`simulate(model, nsim = 100)` on the fitted GAM. With the gratia package
attached, that function draws new *observations* from the fitted beta
distribution at each cell's fitted mean. The model's coefficients are
held fixed; the uncertainty of the fitted albedo-cover relationship is
never sampled. Every `alb_sd`, `alb_lo`, `alb_hi` and the sd and CV maps
in script 7 are therefore the residual scatter of the calibration data
(its beta dispersion), reproduced at each paleo cell, not the model's
uncertainty. The "fraction of data inside the 95% interval" statistic in
script 5 (lines 206-244) checks that the dispersion parameter was
estimated consistently, not that the model is calibrated.
**Why it matters.** The two kinds of uncertainty behave differently.
Observation noise is the same size everywhere and does not grow when the
model extrapolates; coefficient uncertainty grows where the paleo cover
combinations are far from the modern calibration data, which is exactly
where the early-Holocene results live.
**Options.** (i) Keep observation noise, and describe it as such in the
paper. (ii) Replace it with coefficient draws: sample coefficient vectors
from the fitted model's posterior (gratia's `fitted_samples`, or a
multivariate normal from `vcov(model)` applied to the prediction matrix),
which costs seconds per month. (iii) Add both.
**What we need from you.** Which of these did you intend? The manuscript
says "posterior samples", which readers will take to mean (ii).

### A3. 100 or 1,000 draws
The manuscript says 1,000 posterior samples per cell and month; the
scripts draw 100. Which is intended? (This interacts with A1 and A2.)

## B. The calibration model

### B1. The land-cover smooth has one direction with no data in it
**What the code does.** Model 8, the selected model, includes a
three-dimensional smooth `s(OL, ET, ST, bs = "tp", k = 200)`
(`4_calibration_model.R` line 286, and the March version at line 755).
The three fractions always sum to one, so every calibration point lies
on a flat two-dimensional sheet inside the three-dimensional (OL, ET, ST)
space. The smooth has nothing to learn about the direction perpendicular
to that sheet, and `mgcv` reports the fit as rank-deficient: the fitted
March model has rank 444 of 448 coefficients.
**Why it matters.** On the sheet this is harmless. Off the sheet the
smooth is unconstrained, and some paleo rows are off it: script 1
renormalises across all taxa and then drops taxa whose cover class is NA
(`Ericaceae`, `Boraginaceae`, `Plantaginaceae`, `Urticaceae`, lines
54-59), so those rows sum to less than one and are predicted by
extrapolation in the empty direction.
**Options.** (i) Keep the 3-D smooth but renormalise paleo rows to sum to
one before prediction, and check how many rows were affected. (ii) Use a
two-dimensional smooth of two fractions, `s(ET, ST)`, or a compositional
(isometric log-ratio) transform, and refit the ladder.
**What we need from you.** Did you know about the rank deficiency, and do
you have a preference? (ii) changes the model and the results; (i) is a
small correction.

### B2. Calibration on the interpolated field rather than pollen cells
**What the code does.** The all-months calibration reads
`calibration_modern_lct_interp_bluesky.RDS`, the modern slice of the
interpolated product, so it is fitted to all ~2,900 land cells, of which
only ~500 contain pollen sites. The rest are outputs of the interpolation
model. The draft manuscript still says "estimates are made for grid cells
that contain one or more pollen records".
**Why it matters.** Fitting to interpolated cells raises the apparent
sample size and skill of the spatial term, and smooths the cover
heterogeneity the albedo model is meant to learn from; the model is
partly being fitted to another model's output.
**What we need from you.** Is this the intended design, or should the
calibration be fitted to pollen-bearing cells only and the interpolated
field used for prediction alone? Either way the manuscript text needs to
match.

### B2a. The two flavours fit the spatial smooth in different coordinate systems
**Found 2026-09-19** while running the interp pipeline for the first time.

**What the code does.** Scripts 4, 5 and 6 fit the spatial term as
`s(x, y, bs = "gp", k = 500)`, taking whatever columns are named `x` and
`y`. Those columns mean different things in the two flavours:

| Flavour | `x`, `y` are | Range |
|---|---|---|
| non-interp (`lct_paleo_reveals.RDS`) | Albers equal-area metres, with `long`/`lat` held separately | x -3,103,504 to 3,076,936 |
| interp (`lct_*_reveals_interp.RDS`) | **longitude and latitude in degrees**; no projected columns exist | x -171.5 to -53.5 |

In the interp half of `1_veg_lct_prep.R` the `x`, `y` of
`veg_posts_interp_ice.RDS` are passed straight to `get_elev_point(...,
prj = ll_proj)` (line 228) and never projected, so they stay in degrees.

**Why it matters.** A Gaussian-process smooth measures distance between
points, so the units and the geometry matter. In degrees, distance is
anisotropic and latitude-dependent: one degree of longitude is about
105 km at 25°N but only about 38 km at 70°N. The smooth therefore treats
the far north as horizontally compressed relative to the south, which is
exactly the distortion the Albers projection exists to remove, and the
study's largest Holocene changes are in the north. The fitted
length-scale and the effective degrees of freedom of the spatial term
are not comparable between the two flavours either, which may be part of
why our March non-interp results and the talk's interp results differ
over 4 to 6 ka.

**Options.** (i) Leave as is, and state in the methods that the interp
spatial term is fitted on unprojected coordinates. (ii) Project the
interp cell centres to the same Albers grid the non-interp flavour uses,
before calibration, so both flavours and all the published comparisons
share one coordinate system.

**What we need from you.** Was fitting the interp spatial smooth on
degrees intended, or an oversight when the interpolated product was
swapped in? This changes results, so we have not altered it; the first
interp run reproduces the code as written.

### B2b. Winter albedo is missing across the north: polar night
**Found 2026-09-19** in the first interp calibration table.

**What the data show.** The blue-sky albedo has no value for high-latitude
cells in winter, because there is no incoming sunlight to reflect. In the
interp calibration table (2,860 cells):

| Month | Cells with no albedo | Latitudes affected |
|---|---|---|
| December | 1,109 (39%) | every cell above 60°N, 9% of 50-60°N |
| January | 694 (24%) | above 62.5°N |
| November | 400 (14%) | above 66.5°N |
| February | 95 (3%) | far north only |
| March to October | 33 (1%) | above 76.5°N |

**What the code does with them.** The calibration models are fitted with
`na.action = na.omit`, so those rows are dropped silently: the December
model never sees a cell north of 60°N. The prediction step then applies
that model to all 2,860 cells for every time slice, so December albedo
across the whole north is produced by extrapolating both the spatial
smooth and the land-cover smooth into a region and a vegetation range
the model had no data for.

**Why it matters.** This is the month and the region where the paper's
mechanism is strongest: snow masking by vegetation, at high latitude, in
winter. It is also where the Laurentide ice sheet sat, so the
early-Holocene forcing draws on exactly these extrapolated cells. The
spatial term cancels when consecutive slices are differenced (B3), but
the land-cover smooth does not, and in December that smooth was fitted
only on southern vegetation.

**Options.** (i) Keep, and state that winter high-latitude albedo is
extrapolated. (ii) Restrict the reported forcing to months and cells
with calibration support, for example by masking any cell-month whose
latitude lies outside the fitted range. (iii) Weight the annual forcing
by available sunlight, which is near zero exactly where the data are
missing, so the extrapolation would matter much less.

**What we need from you.** Was the winter data gap known, and how do you
want it handled in the maps and in the annual means? Option (iii) may be
the most defensible physically, since a forcing computed where no
sunlight falls is close to meaningless.

**A statistic this distorts (found 2026-09-23).** Script 5's "fraction
of data inside the 95 % interval" divides by all 2,860 cells, so the
polar-night cells with no observation count as misses. The anchored
table therefore shows 0.56 for December, 0.70 for January and 0.80 for
November against 0.90-0.94 elsewhere; on the cells that have data every
month is about 0.92. The winter models are not worse; the denominator
is. Worth fixing before the number is quoted.

### B3. The spatial term cancels through time and may have absorbed the cover effect
**What the code does.** Every prediction uses the same location and
elevation values for a cell in every time slice; only the cover fractions
change. On the link scale the location and elevation terms therefore
cancel in every slice-to-slice difference, and the entire Holocene albedo
signal comes from the shape of the cover smooth alone. That smooth was
fitted alongside a very flexible spatial surface (`s(x, y, bs = "gp",
k = 500)`) on the same modern data.
**Why it matters.** Cover and location are strongly correlated in the
modern data (forest in the east, prairie in the middle, tundra in the
north). A flexible spatial term can take credit for part of the true
cover effect, leaving the cover smooth biased towards zero and the
Holocene forcing understated. The "spatial effects experiment" in scripts
4 and 5 compares fits, not the size of the cover effect.
**What we need from you.** Was this examined, for example by comparing
the cover effect with and without the spatial term, or by spatially
blocked cross-validation? If not, would you like us to?

### B4. Model selection: model 8 is fixed by hand, but the data support it
**Updated 2026-09-20 with the interp AIC table**, which script 4 produced
overnight for all twelve months (`output/calibration/AIC_table.csv`).

**What the code does.** Script 4 prints an AIC table and analysis of
deviance for models 1 to 8 (lines 315-335), but script 5 (line 28) loads
model 8 as the selected model for every month unconditionally.

**What the interp data show.** The hard-coding turns out to encode the
right answer. Model 8 has the lowest AIC in 11 of 12 months, losing
narrowly to model 7 in May, and is never the worst. AIC decreases
monotonically with model complexity in every month:

| | jan | apr | jul | oct | dec |
|---|---|---|---|---|---|
| model 1 | -6583 | -8904 | -12642 | -9449 | -6027 |
| model 8 | -6669 | -9503 | -13032 | -10405 | -6127 |

This supersedes the worry raised from the non-interp May run, where AIC
rose with complexity in a way correctly fitted nested models cannot. On
the interp data the behaviour is orderly.

**What is left of the question.** A formal one: the models are fitted by
REML and compared across differing mean structures, which is not a valid
likelihood comparison (mgcv's own guidance is to use `method = "ML"`
when comparing models that differ in their terms), and models 6 to 8 are
rank deficient because the cover fractions sum to one, so the penalty
term is ambiguous. A referee could object. Given how consistent and
monotone the ordering is, refitting by ML would very likely confirm
model 8 rather than overturn it, so this is tidying rather than a
threat. **Would you like the ladder refitted with `method = "ML"` so the
selection can be defended as stated?**

### B4a. Land cover matters most in autumn, least in midwinter
**Found 2026-09-20 in the interp AIC table.**

The improvement from adding land cover to the model varies strongly by
season. Taking the AIC spread across the ladder within each month as a
measure of how much the cover terms buy:

| jan | feb | mar | apr | may | jun | jul | aug | sep | oct | nov | dec |
|---|---|---|---|---|---|---|---|---|---|---|---|
| 86 | 167 | 331 | 599 | 798 | 486 | 390 | 461 | 891 | 956 | 370 | 100 |

Land cover explains most in September and October, and least in December
and January, by roughly a factor of ten.

**Why it matters.** The paper's mechanism is snow masking: vegetation
changes albedo most where it hides or exposes snow, which should make
winter the season where cover matters most. The data say the opposite.
Two candidate explanations, which point in different directions:

- *Physical.* In midwinter at these latitudes there is little sunlight
  and deep snow cover everywhere, so albedo is high and uniform whatever
  the vegetation; the shoulder seasons, with partial snow and active
  canopy, are when cover discriminates.
- *Artefactual.* Midwinter is exactly when the polar-night gap removes
  the northern cells (B2b): the December model is fitted only south of
  60°N, so the cells where snow masking is strongest are absent from the
  fit. The weak winter signal may be a sampling artefact rather than a
  physical result.

**What we need from you.** Which do you think it is, and is this
seasonality something the paper should report? If it is the second, it
strengthens the case for handling the winter gap explicitly rather than
extrapolating into it.

### B5. Calibration response: centre pixel or cell mean
**What the code does.** Script 2 computes both the native 0.25-degree
albedo at the 1-degree cell centre and the 1-degree cell mean
(`_coarse`), and the calibration uses the centre pixel (lines 190 and
195; script 4 line 17). The predictors are 1-degree cell means.
**Why it matters.** A centre pixel over a lake, a city or a clear-cut is
attributed to the whole cell's cover.
**What we need from you.** Was the centre pixel a deliberate choice?

**Added 2026-09-23, with the specifics.** Script 2 builds the calibration table by sampling the 0.25-degree albedo
raster at each 1-degree cell's centre point (`terra::extract` at a
point returns the pixel under it). So every row of the table pairs a
land-cover fraction that describes the whole 1-degree cell with the
albedo of one quarter-degree pixel, a sixteenth of the cell. The
cell-average albedo is computed in the same script (`resample(method =
"average")`, saved as `..._coarse.RDS`) but is only used for a
diagnostic scatter; script 4 fits to the centre-pixel table. The code
review of 2026-09-18 noted this; recording it here so it reaches you.

Was the centre-pixel choice deliberate, for instance to avoid averaging
in water or ice pixels at coasts and lake margins, and have you tried
fitting to the cell average instead? If the two calibrations differ, the
cell average is the like-for-like match to the 1-degree predictors.

### B6. Albedo values of exactly zero are set to 0.0001
*Checked 2026-09-19: no cell-month in the interp calibration table hits
this replacement, so it affects the non-interp flavour only.*
Script 2 (line 388) replaces zeros with 0.0001 before fitting. On the
logit scale that is about -9, a very influential value for a beta model.
Where do the zeros come from (water, fill values, failed retrievals), and
should those cells be dropped instead?

### B7. Twelve independent monthly models
You said in the meeting that a model with within-year structure would be
better but is out of scope. Should the paper state that "consistent
pattern across months" is an observation rather than a constraint of the
model?


### B8. Present-day ice caps sit in the modern calibration as vegetated cells
The `ice` flag in `veg_posts_interp_ice.RDS` is applied only to slices
of 1,000 BP and older: at 50, 200 and 500 BP no cell is flagged, although
the 1 ka ice polygons contain 48, 35 and 48 of those slices' cells
respectively (point-in-polygon test, 2026-09-25). So 48 of the 2,860
modern cells are present-day ice caps (20 in Alaska west of 100 W, 10
in the Canadian Arctic islands, 18 on Baffin and Labrador), and they
enter the calibration table with land cover assigned by the
interpolation (mean ET 0.30, OL 0.49, ST 0.21) and the satellite's ice
albedo: July mean 0.36 against 0.13 for everything else, April 0.69
against 0.38. They are 1.7 % of the cells but carry the highest albedos
in the dataset and an open-land fraction that describes rock and ice,
not vegetation.

Was leaving them in deliberate? If not, excluding them (or masking with
the 1 ka polygons, which the flag already uses for older slices) is a
one-line change in script 2 that could shift the fitted open-land
albedo, which is the term the whole hindcast rests on.


### B9. Elevation is a single point at the cell centre, at an unstated resolution
Script 1 takes elevation from `elevatr::get_elev_point()` at each cell's
centre coordinate: one spot in a cell 70-100 km across, against land
cover that is a cell average. In flat country it hardly matters; in the
Rockies or the Mexican highlands (the table reaches 3,492 m) the centre
point can sit hundreds of metres from the cell mean, and for 
coastal cells whose centre falls offshore the service returns the sea
floor (the table's minimum is -28 m). The tile resolution queried is
elevatr's default (`z = NULL`, version 0.99.1) and is nowhere stated.
This is the same point-versus-cell mismatch as B5, applied to the second
predictor. Was a cell-mean elevation (e.g. from a DEM averaged over the
cell) considered, and should offshore centres be clipped to zero?


## C. Differencing, ice and forcing

### C0. One ice chronology, plus a second one only for the fraction
**Checked 2026-09-19.** An earlier draft of this question worried that
the pipeline held three unreconciled ice definitions. Testing showed
that two of them are the same thing:

| Source | Form | Used by | In the repo? |
|---|---|---|---|
| `ice` flag in `veg_posts_interp_ice.RDS` | binary, per cell and slice | the vegetation interpolation, to avoid inventing vegetation under ice | yes |
| `map-data/ice/glacier_shapefiles_21-1k.RDS` | 21 polygon sets, 1,000-year steps | `7_plot_preds.R`, for overlays and ICE status | yes |
| `Dalton_QSR_2020_Ice/dalton_interpolated_LC6k.tif` | continuous ice **fraction** | `7a_alb_diff_full.R`, for the vegetation/ice albedo mixing | **no** |

A point-in-polygon test of every cell against the shapefiles reproduces
the `ice` flag exactly at every age tried: 69 of 69 cells at 6 ka, 213
of 213 at 8 ka, 596 of 596 at 10 ka, 780 of 780 at 11 ka, with no
disagreement either way. So the flag was derived from these shapefiles,
and the pipeline really has **one** ice chronology, used consistently
for the vegetation mask and for the maps.

The only reason a second product appears is that script 7a needs a
*fraction* per cell, to mix vegetation and ice albedo by area, whereas
the shapefiles give a yes or no. Dalton supplies a fraction.

**What we need from you.** Could the fraction be computed from the ice
polygons we already have, by rasterising them onto the 1-degree grid
with fractional coverage? That would give the whole pipeline a single
source of truth for where the ice was, and remove the missing Dalton
file from the critical path. The trade-off is chronology: Dalton et al.
2020 is an update to the older reconstruction these polygons appear to
come from, so using the polygons means using the older margins
throughout. Which would you prefer: one consistent older chronology, or
the newer Dalton fraction alongside the older mask and overlays?

One related point either way: `1_veg_lct_prep.R` drops the `ice` column
when it aggregates, so the flag never reaches the predictions and the
pipeline picks ice up again later from a different file. Should it be
carried through?

**A coverage note (2026-09-25).** The flag itself is consistent: at every
slice it equals the cells present in the product that fall inside the
nearest polygon set (ties to the younger). Where the counts look odd it
is the product's cell coverage: at 4,500 BP only 41 cells are flagged
against 55 at 4,000 because 14 cells that exist at 4,000 are absent from
the product at 4,500. That is the 1,814 missing cell-slices (2.5 %) of
script 1's header showing through; which cells drop out at which
slices, and why, has not been characterised.

**The two sources disagree at the modern slice (2026-09-25).** At 50 BP
script 7's polygon test flags 48 cells as ice while script 7a's Dalton
raster puts 28 cells over half ice (156 with any ice at all). Both are
"today", so this is a direct measure of how far the two chronologies
differ, independent of any dating question.

### C0a. `albedo_glacier_monthly.csv` cannot be sourced; what should the values be?
The code needs twelve rows with the columns `month`, `ice_albedo_fixed`
and `ice_albedo_sc` (`7a:264-268`), plus `ice_albedo` for
`7_plot_preds.R` (`7:258-262`). This is not a published dataset, it is a
set of chosen values, so there is nothing for us to download.

Its influence is large: it sets the albedo of every ice-covered cell, so
it drives the deglaciation forcing that dominates 12 to 8 ka.

**What we need from you.** The file if you have it, or the values and
where they came from. Failing that, may we derive them from the
blue-sky albedo product over present-day ice and document the choice?
That would at least be internally consistent, same product and same
months as the calibration. We would also need to know what distinguishes
`ice_albedo_fixed` from `ice_albedo_sc` ("scaled" by what?).

### C0b. The Dalton raster: can we reconstruct it?
`dalton_interpolated_LC6k.tif` is not Dalton et al. 2020's published
data; it is their ice margins interpolated to the LandCover6k time
slices and rasterised to a per-cell fraction, a derived product specific
to this project. The originals are behind the journal paywall with no
open repository we could find, and the interpolation method is not
recorded anywhere in the repository.

**What we need from you.** The file itself, or failing that the script
that made it. Searched 2026-09-19: Dalton et al. 2020's margins are not
deposited in any open repository we can find and the paper is
paywalled, so we cannot rebuild the file independently. And because
`dalton_interpolated_LC6k.tif` is not Dalton's published data but their
margins interpolated to the LandCover6k slices by someone on the
project, even the original shapefiles would leave us guessing at the
resampling. **This file is the only route to reproducing the paper's
forcing numbers**; everything below is a substitution that changes
results.

*Substitutes, in case the file is gone.* (i) Rasterise the ice polygons
already in the repository to a fractional coverage (see C0): no new data
needed, and it gives the pipeline a single ice chronology, but it is the
older reconstruction. (ii) NADI-1, Dalton et al. 2023, is openly
available on Zenodo (doi:10.5281/zenodo.8161764, CC-BY-4.0, 147
shapefiles): a newer chronology at 500-year steps from 25 to 1 ka, which
happens to match this project's slice spacing so it would need little
interpolation, and it ships minimum and maximum margins alongside the
optimal one. That last point is worth noting even if we do not switch
now: the pipeline currently carries no ice-extent uncertainty at all,
which your EGU speaker notes acknowledge, and NADI-1 would let that be
quantified rather than just stated. Either substitute means the paper
must cite the chronology actually used.

### C1. Which ice representation the paper reports
**What the code does.** Script 7a computes two representations of ice in
each cell and slice: a threshold (cell is ice if the Dalton ice fraction
exceeds 0.5) and an area-weighted mix of vegetation and ice albedo. Each
is computed with a fixed glacier albedo and with a scaled one, and script
8 computes forcing for every combination.
**What we need from you.** Which combination do the talk and paper
report, and how different are the continental totals between them?

### C2. Ice readvances are averaged away
**What the code does.** Script 7a (lines 452-459) looks for cells where
the ice fraction increases from an older to a younger slice, and replaces
that value by the mean of its neighbours in time. Real readvances are
erased; the adjustment is applied once, not repeated, and it fails with an
error if the increase occurs in the first pair. A later sum with
`na.rm = TRUE` (lines 526-530) turns such pairs into a confident zero
albedo change that still receives a kernel.
**Why it matters.** The early-Holocene forcing is dominated by ice, so
the rule for handling the ice chronology sets the largest numbers.
**What we need from you.** Is suppressing readvances deliberate? If so we
will clamp the chronology to monotone retreat cleanly; if not we will
keep real readvances.

**Two code-level consequences, found 2026-09-23.** (i) The one-step
smoothing is applied once, not iterated; 2,844 pairs in the anchored run
still show ice growing forward in time afterwards. (ii) Where ice
advances ACROSS the 50 % threshold (young end ice, old end vegetation),
both the vegetation and the ice difference are `NA` and `rowSums(na.rm
= TRUE)` turns them into 0, a silent "no change" that then receives a
kernel: 36 pairs. And if the offending step were ever the first pair of
a series the index arithmetic would hit position 0 and the script would
stop; it has not happened in the data so far.

### C3. The three kernels are not like for like
**Verified on 2026-09-19** for HadGEM3 and CAM5, and **on 2026-09-21**
for CACK, by downloading the kernels and opening them (README.md records
provenance, licences and sizes).

**What the code does and what the files contain.**

| Script reads | Variable long name | Flux level | Sky | Units |
|---|---|---|---|---|
| `8:58` HadGEM3 `albedo_sw_cs` | "SW Surface albedo clear-sky kernel" | **top of atmosphere** | clear-sky | W/m² per 1% |
| `8:163` CAM5 `FSNSC` | "Clearsky net solar flux at **surface**" | **surface** | clear-sky | W/m² per 1% |
| `8:197` CACK `CACK`, `level=month`, `band=3` | "Temporally-explicit kernels" | top of atmosphere | all-sky | W/m² per unit albedo |

**CACK's units are different, and the code already handles it.** CACK
declares `Units = W/m^2` for a unit (0 to 1) albedo change, not per 1%.
That is why `8:295-301` uses `alb_diff * (-rk_cack)` with no factor of
100, while HadGEM3 and CAM5 get `alb_diff * 100 * kernel`. The sign flip
is also right: CACK is stored positive (13 to 258 W/m² over our cells),
whereas HadGEM3 and CAM5 are stored negative. So all three conversions
are dimensionally consistent as written.

**But `band = 3` is a year, not a sky condition.** The CACK file's
fourth dimension is documented as `Year: Years after 2000 AD`, with 16
entries. `raster(..., level = month, band = 3)` therefore pulls the
kernel for **2003 alone** — one arbitrary satellite year — rather than a
climatology. The file also contains `CACK CM`, described as
"Climatological mean kernel", which is almost certainly what a Holocene
study wants, and which would remove a source of interannual noise that
differs between the three kernels.

**CACK also ships uncertainty layers.** `Sigma_total`, `Sigma_me` (model
error) and `Sigma_du` (data uncertainty) are in the same file at the same
resolution, with climatological-mean twins. These would let the kernel
contribute a genuine uncertainty band to the forcing (see section A)
rather than being treated as exact.

**Good news on units for the other two.** Both files are per 1% albedo change: HadGEM3
states `units = W/m2/%`, and Pendergrass et al. (2018, §2.1) define their
albedo kernel as "the change in radiative flux for a 1 % change in
surface albedo". So the `alb_diff * 100 * kernel` convention at
`8:256-301` is right for both, and the talk's "W/m²/%" is correct.

**The problem.** The two kernels answer different questions: HadGEM3
gives the change in flux at the top of the atmosphere, CAM5 the change at
the surface. They are not comparable, so "radiative forcing was not
sensitive to kernel" is comparing unlike quantities. The like-for-like
CAM5 variable is `FSNTC`, "Clearsky net solar flux at top of model",
which is in the same file, so the fix is a one-word change.

**Also available at no cost.** Each file contains its all-sky twin
(HadGEM3 `albedo_sw`, CAM5 `FSNT`/`FSNS`), so the clear-sky versus
all-sky test in C4 needs no new download.

**What we need from you.** (a) Was top of atmosphere the intended flux
level throughout? If so, may we switch CAM5 to `FSNTC` and re-run the
comparison? (b) Was `band = 3` meant to select the year 2003, or was the
climatological mean `CACK CM` intended? (c) CACK is all-sky while HadGEM3
and CAM5 are read as clear-sky, which is a second way the three are not
like for like, on top of the flux-level mismatch; was that deliberate?
(d) The kernel grids are aligned to the data by arithmetic on longitude
and latitude (`8:230-250`) with the check plots commented out; was that
verified? We have now re-run that arithmetic against the 2,870 interp
cells and all three kernels return values with no missing cells, which is
consistent with correct alignment but does not prove the grids are not
transposed.

### C4. Clear-sky, pre-industrial kernels across the Holocene
The HadGEM kernel is clear-sky and pre-industrial. Clear-sky albedo
kernels are typically 1.5 to 2 times larger than all-sky because clouds
mask the surface, and early-Holocene summer insolation at high latitudes
was tens of W/m² above pre-industrial. What is the case for this choice,
and would an all-sky kernel change the headline numbers?

**Now measured, 2026-09-21.** The first complete interp run of script 8
answers the second half of the question: yes, substantially. Mean
forcing per slice-pair over all cells and months, `rf_*_veg_ice_thresh`:

| slice-pair (BP) | HadGEM3 (clear) | CAM5 (clear) | CACK (all-sky) | CACK / HadGEM3 |
|---|---|---|---|---|
| 11,000 | 2.270 | 2.377 | 1.205 | 0.53 |
| 10,500 | 2.945 | 3.076 | 1.618 | 0.55 |
| 10,000 | 2.428 | 2.553 | 1.447 | 0.60 |
| 8,500 | 3.383 | 3.556 | 1.810 | 0.54 |
| 8,000 | 2.594 | 2.741 | 1.386 | 0.53 |

HadGEM3 and CAM5 agree to within about 5%, which is the basis for the
talk's claim that the result is not sensitive to the choice of kernel.
But both are read as clear-sky, so that agreement is between two
like-for-like quantities and does not test the choice. CACK, the only
all-sky kernel of the three, gives consistently **just over half** the
forcing, a ratio of 0.53 to 0.60. That sits squarely in the 1.5 to 2
times range quoted above for clear-sky over all-sky.

So the kernel choice moves the headline number by roughly a factor of
two, and the claim of insensitivity does not survive including CACK.
This needs resolving before the numbers are quoted. It is also separable
from the top-of-atmosphere versus surface mismatch in C3: switching CAM5
to `FSNTC` and comparing all-sky against all-sky would isolate the two
effects, and both variables are already in the files we hold.

**Caveat on these figures.** They are unweighted means over cells and
months, taken directly from `output/forcing/RF_holocene_all_cases.RDS`;
the talk's bar plots are per-period and area-weighted, so the ratio is
the meaningful quantity here rather than the absolute values.

### C5. The comparison with modern forcing agents
The talk compares the Holocene forcing with IPCC forcing from modern
agents. The Holocene number is local to North American land, clear-sky,
and per interval; the IPCC numbers are global means, all-sky, and
cumulative since 1750. North American land is a few percent of Earth's
surface. What is the fair comparison: the Holocene forcing expressed as a
global mean, or the modern agents expressed regionally?

**Attempted 2026-09-21, and the choice decides the headline claim.**
`scripts/9_forcing_barplot.R` now builds the slide 18 chart from
`output/forcing/RF_holocene_all_cases.RDS`. No code for it existed in
the repository, so every aggregation choice is ours and is listed in
that script's header. The study area works out at **3.8% of Earth's
surface**, and the two normalisations differ by a factor of about 27:

| period | domain mean (W/m², HadGEM3) | global equivalent (W/m²) |
|---|---|---|
| 8 - 10 ka | 8.04 | 0.303 |
| 10 - 12 ka | 7.17 | 0.270 |
| 6 - 8 ka | 2.89 | 0.109 |
| 4 - 6 ka | -1.74 | -0.066 |
| 0.05 - 0.5 ka | -1.17 | -0.044 |

IPCC AR6 gives methane 0.544 W/m² (1750-2019, global mean). On the
**global-equivalent** basis the early-Holocene peak is 0.30 W/m², about
56% of methane, which matches the talk's "comparable to modern methane
forcing" well. On the **domain-mean** basis it is 8.0 W/m², roughly
fifteen times methane, which would not be described that way. So the
talk's own wording implies the global-equivalent normalisation was used.

**Please confirm** that is what you did, because it is the single
biggest lever on the headline number, and the script currently assumes
it. Related assumptions in the same script that we would like checked:
(a) forcing variant `veg_ice_thresh` rather than one of the nine others,
notably the `_parts` family that mixes vegetation and ice albedo by area
fraction instead of by threshold; (b) slice-pairs **summed** within each
period, which telescopes to the endpoint difference, rather than
averaged; (c) months averaged with equal weight; (d) cells area-weighted
by the `area` column. A sensitivity plot over (a) is at
`figures/forcing_barplot_variant_sensitivity.pdf`.

**The layout now matches slide 18, but the numbers do not.** Reading the
bars off `ppt/media/image37.png` in `writing/dawson_EGU.pptx` and
comparing with our global-equivalent values (HadGEM3, `veg_ice_thresh`):

| period (ka) | slide 18 | ours | ratio |
|---|---|---|---|
| 0.05 - 0.5 | -0.38 | -0.044 | 8.6 |
| 0.5 - 2 | -0.17 | -0.047 | 3.6 |
| 2 - 4 | 0.22 | 0.063 | 3.5 |
| 4 - 6 | ~0.00 | -0.066 | - |
| 6 - 8 | 0.36 | 0.109 | 3.3 |
| 8 - 10 | 0.37 | 0.303 | 1.2 |
| 10 - 12 | 0.72 | 0.270 | 2.7 |

The ratio is not constant, so this is **not** a normalisation or unit
difference that we could simply correct. We checked all six forcing
variants and none is closer: the best has essentially the same error as
the worst. The shape differs too. On the slide the forcing grows
monotonically into the past and peaks at 10-12 ka; ours peaks at 8-10 ka
and dips negative at 4-6 ka where the slide is flat. The slide's
late-Holocene cooling is also far deeper than ours.

**Andria confirmed on the call that slide 18 is the interp version**, and
the code that made it has now been recovered from git history: commit
`383002d` (2 April 2024, twelve days before EGU 2024), `8_radiative.R`
lines 584-628. It was marked "incorrect now" and commented out in that
commit, then deleted in `aba7e1a` (Feb 2025), so it was absent from the
code we received. Its recipe differs from our first attempt on nearly
every assumption:

| choice | slide 18 code (Apr 2024) | our first attempt |
|---|---|---|
| input | script 7's `alb_interp_preds_diffs`: 7 coarse pairs, one per period | 7a's 24 consecutive pairs, summed |
| months | **feb, may, aug, nov only** | all twelve |
| ice | binary-flagged cells masked out | ice fraction via `veg_ice_thresh` |
| aggregation | **plain unweighted mean** over cells x months (`mean_forcing`) | area-weighted, global-equivalent |
| kernel | HadGEM3 | HadGEM3 |

So the slide is a **domain mean over the study area, not a global
equivalent**, and the "comparable to modern methane" comparison on the
slide sets a regional mean beside a global one. That is the C5 question
answered, in the direction that needs discussing.

**Rerunning her exact recipe on today's data** (`scripts/9_forcing_barplot.R`,
`figures/forcing_barplot_slide18_egu2024recipe.pdf`) reproduces the
late-Holocene shape but not the numbers:

| period (ka) | slide 18 | her recipe, today's data |
|---|---|---|
| 0.05 - 0.5 | -0.38 | -1.27 |
| 0.5 - 2 | -0.17 | -0.94 |
| 2 - 4 | 0.22 | 0.76 |
| 4 - 6 | ~0.00 | -2.14 |
| 6 - 8 | 0.36 | 0.05 |
| 8 - 10 | 0.37 | **-2.38** |
| 10 - 12 | 0.72 | 3.97 |

Magnitudes are 3 to 5 times larger and 8-10 ka changes sign. Since the
recipe is now hers, the residual is in the **data**: the April 2024
versions of `veg_posts_interp_ice.RDS` and the calibration tables are not
in git (the only committed copy is the one you sent on 2026-09-18), and
no intermediate table or figure was ever committed. **Could you send the
land-cover posterior and calibration data as they were in April 2024, or
the saved forcing table / figure file behind the slide?** Either would
turn this into a direct diff.

The IPCC panel does match: CO2 2.16, methane 0.54, water vapour 0.05,
albedo (land use) -0.20 and aerosols -1.06 are AR6 values and reproduce
the slide's bottom panel exactly, which confirms the AR6 source and that
the slide's x axis really is a global-mean W/m² scale shared by both
panels. That is strong evidence for the global-equivalent reading of
assumption A8.

### C6. Consecutive-slice differences and interval length
Forcing is defined per consecutive pair of slices. The pairs span
different lengths (150, 300, 500 years) and do not accumulate to a change
relative to a baseline. Should a fixed reference slice be used, or forcing
be expressed per unit time?

### C7. The 11.5 ka slice is labelled 12 ka
Script 7 relabels age 11,500 as 12,000 for plotting (line 100); script 7a
does not. Is 12 ka the intended label, and is it the same slice? (The
broader time-slice question is in the general file.)

## D. Land cover

### D1. Taxon-to-class mapping in the north
`taxon2LCT_translation_v2.0.csv` maps Betula, Alnus and Salix to
summergreen trees and drops Ericaceae, so dwarf-birch tundra looks like
deciduous forest to the model, and open land lumps prairie, tundra and
cropland with very different albedo. Was this examined? It matters most
in the north, where the largest Holocene changes are.

### D2. Age uncertainty and binning
How are samples whose age posteriors straddle a bin boundary assigned to
time slices? Sharp events such as the hemlock decline can be smeared or
sharpened by that choice.

### D3. The 1,814 absent cell-slices: all at the edges, none used downstream
Characterised 2026-09-25. The land-cover product has 2,870 cells x 25
slices = 71,750 cell-slices, of which 1,814 are absent. All of them
belong to 211 cells, and every one of those cells lies outside the band
the pipeline uses: 114 south of 27 N (1,422 absent cell-slices) and 97
north of 74 N (392). No interior cell is missing any slice, so script
8's 27-74 N trim removes every incomplete cell before the forcing is
computed, and script 7a's coverage check finds exactly these 211.
**Conclusion: harmless for the modelling as run.** Two patterns are still
worth understanding as data quality:

- South of 27 N the coverage shrinks back in time in steps: 10 cells
  (a strip along 17.5 N, 100.5 W to 91.5 W, the grid's southern edge)
  exist only at 1,000-2,000 BP; 84 cells are absent from 5,500 BP back;
  all 114 are absent from 8,000 BP back. That reads like the southern
  reach of the pollen-site network thinning into the past.
- North of 74 N, 66 cells are absent at exactly three slices, 200, 4,500
  and 6,000 BP, and present at every other slice including older ones;
  97 are absent at 11,000 and 11,500 BP. Three isolated slices is not a
  geological pattern; it looks like an artefact of the interpolation run
  (and it is why the ice-flag count at 4,500 BP, 41, is below its
  neighbours: 14 flagged cells are simply absent at that slice).

Is the southern thinning intended (no pollen data), and do you know what
happened at 200, 4,500 and 6,000 BP in the north?


## E. Validation

### E1. Independent check of the hindcasts
Is there any out-of-sample test of the hindcast albedo? The last 150
years of Euro-American clearance, with land-survey or HYDE land cover and
published deforestation forcing estimates, looks like the natural one.
