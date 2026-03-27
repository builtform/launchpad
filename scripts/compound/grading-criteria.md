# Evaluator Grading Criteria

This document defines what "pass" and "fail" mean for each grading dimension.
The evaluator agent reads this for calibration. The generator can also read this
to understand the quality bar before implementation.

## Design

Does the UI feel like a coherent whole rather than a collection of parts?

### Pass

- Consistent color palette and typography across all pages
- Proper spacing and visual hierarchy (headings, body, captions are distinct)
- Layout is correct at 375px, 768px, and 1440px
- No overlapping or clipped elements at any breakpoint
- Interactive elements are reachable with adequate touch targets on mobile
- No horizontal scrolling on mobile

### Fail (any one of these)

- Layout breaks at any breakpoint (overlapping elements, broken grid)
- Text overflows its container or becomes unreadable
- Buttons or links are unreachable on mobile
- No visual hierarchy (everything looks the same weight)
- Inconsistent spacing or alignment between similar elements

## Originality

Is there evidence of custom decisions, or is this generic AI template output?

### Pass

- Colors, fonts, and layout patterns are customized to the project's domain
- No telltale signs of AI-generated defaults (purple gradients, Inter font, stock card layouts)
- Deliberate creative choices visible (custom icons, domain-specific metaphors, thoughtful defaults)
- A human designer would recognize intentional decisions

### Fail (any one of these)

- Output is recognizable as unmodified AI template (default colors, boilerplate structure)
- Uses stock patterns without customization (generic hero section, Lorem Ipsum, placeholder images)
- No evidence that design decisions were informed by the project's domain or audience

## Craft

Is the implementation complete, polished, and handles edge cases?

### Pass

- Loading states present on all data-fetching pages
- Error states handled (network failure, invalid input, empty data)
- Empty states present (what users see when there's no data yet)
- No unhandled JavaScript errors in the browser console
- Forms validate input and provide clear feedback
- Transitions and animations are smooth (no janky renders)

### Fail (any one of these)

- Missing loading states (content appears without transition)
- Missing error handling (unhandled API failures, raw error messages)
- Missing empty states (blank page when no data exists)
- Console shows unhandled JavaScript errors during normal usage
- Hardcoded or placeholder data in the UI

## Functionality

Does every documented user flow work end-to-end when tested in the browser?

### Pass

- All user flows documented in the PRD complete successfully
- Forms validate input and submit correctly
- API calls return expected responses
- Navigation works (links, buttons, back/forward)
- Clicking buttons does what they should
- No stub features (features that exist in code but don't work in the browser)

### Fail (any one of these)

- A core user flow is broken (clicking a button does nothing)
- A feature exists in code but doesn't work in the browser
- API endpoints return errors that aren't handled by the UI
- Forms accept invalid input or fail silently on submit
- Navigation leads to 404 pages or dead ends

## Evidence Collection

The evaluator must use Playwright MCP to collect evidence:

1. Navigate to each page in the application
2. Screenshot at 375px, 768px, and 1440px widths
3. Click every button, fill every form, test every user flow
4. Check browser console for JavaScript errors
5. Test API endpoints through the UI (not directly via curl)

Evidence must reference specific pages, elements, and breakpoints.
"The layout looks fine" is not evidence. "Screenshot at 375px shows the signup
form centered with no overflow" is evidence.
