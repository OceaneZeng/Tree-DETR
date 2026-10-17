"""GT-conditioned read-only diagnostics, not detection AP or unknown recall."""
import torch
from util.box_ops import box_cxcywh_to_xyxy, box_iou


@torch.no_grad()
def probe_batch(outputs, targets, matcher, known):
    """One row per visible GT. Detection coverage is not one-to-one AP matching."""
    indices = matcher(outputs, targets)
    rows = []
    categories = torch.as_tensor(known, device=outputs['pred_logits'].device)
    for b, target in enumerate(targets):
        logits = outputs['pred_logits'][b, :, known]
        labels = target['labels'].to(logits.device)
        if not torch.isin(labels, categories).all():
            raise ValueError('Probe received a label outside the released known classes')
        if not len(labels):
            continue
        overlaps = box_iou(box_cxcywh_to_xyxy(outputs['pred_boxes'][b]),
                          box_cxcywh_to_xyxy(target['boxes'].to(logits.device)))[0]
        obj = outputs['pred_objectness'][b].sigmoid()
        novelty = outputs['pred_novelty'][b].sigmoid()
        unknown = obj * novelty
        predictions = categories[logits.argmax(-1)]
        scores = {'hierarchical': logits.softmax(-1) * (obj * (1 - novelty))[:, None],
                  'focal': logits.sigmoid() * obj[:, None],
                  # Isolate novelty suppression: same softmax and same unknown score.
                  'hierarchical_without_novelty_gate': logits.softmax(-1) * obj[:, None]}
        selected = {}
        for mode, score in scores.items():
            combined = torch.cat((score, unknown[:, None]), -1)
            for limit in (50, 300):
                keep = torch.zeros_like(combined, dtype=torch.bool).flatten()
                keep[combined.flatten().topk(min(limit, combined.numel())).indices] = True
                selected[f'{mode}_top{limit}'] = keep.reshape_as(combined)[:, :-1]
        matched = {int(t): int(q) for q, t in zip(*indices[b])}
        for t, label in enumerate(labels):
            column = int(torch.where(categories == label)[0][0])
            covered = overlaps[:, t] > .5
            row = {'image_id': int(target['image_id'].item()), 'class_id': int(label),
                   'gt_index': t, 'any_box_iou50': bool(covered.any()),
                   'correct_argmax_box_iou50': bool((covered & (predictions == label)).any()),
                   'best_iou': float(overlaps[:, t].max()), 'matched': t in matched}
            for name, keep in selected.items():
                row[name] = bool((covered & keep[:, column]).any())
            if t in matched:
                q = matched[t]
                row.update(matched_iou=float(overlaps[q, t]),
                           matched_correct_argmax=bool(predictions[q] == label),
                           matched_objectness=float(obj[q]), matched_novelty=float(novelty[q]),
                           matched_gt_sigmoid=float(logits[q, column].sigmoid()),
                           matched_gt_softmax=float(logits[q].softmax(-1)[column]),
                           matched_novelty_above_half=bool(novelty[q] > .5))
            rows.append(row)
    return rows


def summarize(rows):
    flags = ['any_box_iou50', 'correct_argmax_box_iou50', 'matched'] + [
        f'{mode}_top{limit}' for mode in ('hierarchical', 'focal', 'hierarchical_without_novelty_gate')
        for limit in (50, 300)]
    matched = [r for r in rows if r['matched']]
    result = {'gt_count': len(rows), 'counts': {key: sum(r[key] for r in rows) for key in flags},
              'percent_of_gt': {key: 100 * sum(r[key] for r in rows) / len(rows) if rows else None
                                for key in flags}}
    keys = ('matched_iou', 'matched_objectness', 'matched_novelty', 'matched_gt_sigmoid',
            'matched_gt_softmax', 'matched_correct_argmax', 'matched_novelty_above_half')
    result['matched_means'] = {key: sum(r[key] for r in matched) / len(matched) if matched else None
                               for key in keys}
    return result


def run_probe(args, saved, checkpoint, manifest, identity):
    import json
    from tools.owod.diagnose_learning import make_loader
    from tools.owod.manage_data import prepare_fit_data
    from tools.owod.gnn_calibration import load_detector, move_targets
    from tools.owod.screening_data import write_json
    annotation = prepare_fit_data(args.manifest, args.screening, args.output / 'data', args.images, args.seed)
    _, loader = make_loader(manifest['image_root'], annotation, args.batch_size, args.workers)
    model, criterion = load_detector(saved, checkpoint, torch.device(args.device))
    model.eval()
    rows = []
    with torch.no_grad(), (args.output / 'objects.jsonl').open('w') as handle:
        for index, (samples, targets) in enumerate(loader, 1):
            targets = move_targets(targets, torch.device(args.device))
            outputs = model(samples.to(args.device))
            batch = probe_batch(outputs, targets, criterion.matcher, saved.owod_known_class_ids)
            rows.extend(batch)
            for row in batch:
                handle.write(json.dumps(row) + '\n')
            if index % 20 == 0:
                print(f'Probe: {index}/{len(loader)} batches, {len(rows)} visible GT', flush=True)
    report = {'overall': summarize(rows),
              'per_class': {str(c): summarize([r for r in rows if r['class_id'] == c])
                            for c in saved.owod_current_class_ids},
              'note': 'Current-class GT from deterministic increment training subset; eval transforms, '
                      'no optimization, no EMA reconstruction. GT coverage is not AP/U-Recall; '
                      'one query may cover multiple GT. Counterfactual gate removal is diagnostic only.',
              **identity}
    write_json(args.output / 'supervision.json', report)
    write_json(args.output / 'complete.json', {'kind': 'supervision_probe', **identity})
    print(json.dumps(report['overall'], indent=2), flush=True)
