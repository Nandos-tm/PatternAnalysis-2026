        ),
        image_cache=image_cache,
    )
    train_loader = DataLoader(
        pair_ds, batch_size=args.batch_size, shuffle=True, num_workers=args.workers,
        pin_memory=device.type == "cuda", persistent_workers=args.workers > 0,
    )
    val_ds = ISICImageDataset(
        val_df,
        paths,
        make_transform(args.image_size, resize=image_cache is None),
        image_cache=image_cache,
    )
    val_loader = DataLoader(
        val_ds, batch_size=64, shuffle=False, num_workers=args.workers,
        pin_memory=device.type == "cuda", persistent_workers=args.workers > 0,
    )

    model = SiameseNetWithClassifier(args.embedding_dim, pretrained=not args.no_pretrained).to(device)
    optimizer = torch.optim.AdamW(model.parameters(), lr=args.learning_rate, weight_decay=args.weight_decay)
    criterion = nn.BCEWithLogitsLoss()
    use_amp = device.type == "cuda"
    # Prefer BF16 where available; FP16 uses a scaler to protect small gradients.
    # On CPU, autocast and scaling are disabled.
    amp_dtype = torch.bfloat16 if use_amp and torch.cuda.is_bf16_supported() else torch.float16
    scaler = torch.amp.GradScaler("cuda", enabled=use_amp and amp_dtype == torch.float16)
    best_ap, start_epoch, history = -1.0, 0, []
    last_path, best_path = output / "last.pt", output / "best.pt"
    if args.resume:
        # Resume the optimiser and scaler as well as the weights so the next
        # update continues from the saved training state.
        checkpoint = torch.load(last_path, map_location=device, weights_only=False)
        model.load_state_dict(checkpoint["model"])
        optimizer.load_state_dict(checkpoint["optimizer"])
        scaler.load_state_dict(checkpoint["scaler"])
        start_epoch = checkpoint["epoch"] + 1
        best_ap, history = checkpoint["best_ap"], checkpoint["history"]

    for epoch in range(start_epoch, args.epochs):
        pair_ds.set_epoch(epoch)
        model.train()
        totals = np.zeros(3, dtype=np.float64)
        started = time.time()
        for a, b, same, y_a, y_b in train_loader:
            a, b = a.to(device), b.to(device)
            same, y_a, y_b = same.to(device), y_a.to(device), y_b.to(device)
            optimizer.zero_grad(set_to_none=True)
            with torch.autocast(device_type=device.type, dtype=amp_dtype, enabled=use_amp):
                z_a, z_b, logit_a, logit_b = model(a, b)
                # The metric term shapes the embedding space; the BCE term
                # trains the auxiliary head to classify each endpoint directly.
                metric_loss = contrastive_loss(z_a, z_b, same, args.margin)
                class_loss = 0.5 * (criterion(logit_a, y_a) + criterion(logit_b, y_b))
                loss = metric_loss + args.class_loss_weight * class_loss
            scaler.scale(loss).backward()
            scaler.step(optimizer)
            scaler.update()
            totals += np.array([loss.item(), metric_loss.item(), class_loss.item()]) * len(same)

        model.eval()
        logits, labels, names = [], [], []
        with torch.inference_mode():
            for x, y, image_names in val_loader:
                x = x.to(device)
                with torch.autocast(device_type=device.type, dtype=amp_dtype, enabled=use_amp):
                    score = model.classify(x).float()
                logits.extend(score.cpu().numpy().tolist())
                labels.extend(y.numpy().tolist())
                names.extend(image_names)
        # AP is useful for this highly imbalanced validation set; AUROC is also
        # recorded to describe ranking performance across class thresholds.
        ap = float(average_precision_score(labels, logits))
        auc = float(roc_auc_score(labels, logits))
        row = {
            "epoch": epoch + 1,
            "train_total_loss": totals[0] / len(pair_ds),
            "train_contrastive_loss": totals[1] / len(pair_ds),
            "train_classification_loss": totals[2] / len(pair_ds),
            "val_ap": ap,
            "val_auroc": auc,
            "seconds": time.time() - started,
        }
        history.append(row)
        probabilities = 1 / (1 + np.exp(-np.clip(np.asarray(logits), -40, 40)))
        predictions = pd.DataFrame({
            "image_name": names, "target": labels, "score_logit": logits,
            "score_probability": probabilities,
        })
        # Keep the weights and predictions from the same best-AP epoch.
        if ap > best_ap:
            best_ap = ap
            torch.save({
                "model": model.state_dict(), "epoch": epoch, "val_ap": ap,
                "config": vars(args),
            }, best_path)
            predictions.to_csv(output / "best_val_scores.csv", index=False)
        torch.save({
            "model": model.state_dict(), "optimizer": optimizer.state_dict(),
            "scaler": scaler.state_dict(), "epoch": epoch, "best_ap": best_ap,
            "history": history,
        }, last_path)
        pd.DataFrame(history).to_csv(output / "history.csv", index=False)
        print(row)
    print(f"Best validation AP: {best_ap:.6f}; checkpoint: {best_path}")


if __name__ == "__main__":
    main()
