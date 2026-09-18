/*
 * Copyright (c) Meta Platforms, Inc. and affiliates.
 *
 * This software may be used and distributed according to the terms of the
 * GNU General Public License version 2.
 */

//! Backsyncer
//!
//! Library to sync commits from source repo to target repo by following bookmark update log
//! and doing commit rewrites. The main motivation for backsyncer is to keep "small repo" up to
//! date with "large repo" in a setup where all writes to small repo are redirected to large repo
//! in a push redirector.
//! More details can be found here - <https://fb.quip.com/tZ4yAaA3S4Mc>
//!
//! Target repo tails source repo's bookmark update log and backsync bookmark updates one by one.
//! The latest backsynced log id is stored in mutable_counters table. Backsync consists of the
//! following phases:
//!
//! 1) Given an entry from bookmark update log of a target repo,
//!    find commits to backsync from source repo into a target repo.
//! 2) Rewrite these commits and create rewritten commits in target repo
//! 3) In the same transaction try to update a bookmark in the source repo AND latest backsynced
//!    log id.

use std::collections::HashSet;
use std::iter::once;
use std::iter::repeat;
use std::sync::Arc;
use std::sync::atomic::AtomicBool;
use std::sync::atomic::Ordering;
use std::time::Duration;
use std::time::Instant;

use anyhow::Error;
use anyhow::bail;
use anyhow::format_err;
use blobstore::Loadable;
use bonsai_git_mapping::BonsaiGitMapping;
use bonsai_globalrev_mapping::BonsaiGlobalrevMapping;
use bonsai_globalrev_mapping::BonsaiGlobalrevMappingEntry;
use bonsai_hg_mapping::BonsaiHgMapping;
use bookmarks::BookmarkCategory;
use bookmarks::BookmarkKey;
use bookmarks::BookmarkKind;
use bookmarks::BookmarkPagination;
use bookmarks::BookmarkPrefix;
use bookmarks::BookmarkTransactionError;
use bookmarks::BookmarkUpdateLog;
use bookmarks::BookmarkUpdateLogArc;
use bookmarks::BookmarkUpdateLogEntry;
use bookmarks::BookmarkUpdateLogId;
use bookmarks::BookmarkUpdateLogRef;
use bookmarks::BookmarkUpdateReason;
use bookmarks::Bookmarks;
use bookmarks::BookmarksArc;
use bookmarks::BookmarksRef;
use bookmarks::Freshness;
use cloned::cloned;
use commit_graph::CommitGraph;
use commit_graph::CommitGraphRef;
use commit_graph::CommitGraphWriter;
use context::CoreContext;
use cross_repo_sync::CandidateSelectionHint;
use cross_repo_sync::CommitSyncContext;
use cross_repo_sync::CommitSyncData;
use cross_repo_sync::CommitSyncOutcome;
use cross_repo_sync::find_toposorted_unsynced_ancestors;
use cross_repo_sync::sync_commit;
use dbbookmarks::SqlBookmarks;
use filenodes::Filenodes;
use filestore::FilestoreConfig;
use futures::Future;
use futures::FutureExt;
use futures::StreamExt;
use futures::TryStreamExt;
use futures::future;
use futures::stream;
use futures_stats::TimedTryFutureExt;
use git_source_of_truth::GitSourceOfTruthConfig;
use metaconfig_types::RepoConfig;
use metaconfig_types::RepoConfigRef;
use mononoke_macros::mononoke;
use mononoke_types::ChangesetId;
use mononoke_types::Globalrev;
use mononoke_types::RepositoryId;
use mutable_counters::MutableCounters;
use mutable_counters::MutableCountersArc;
use mutable_counters::SqlMutableCounters;
use mutable_counters::validate_counter_name;
use phases::Phases;
use pushrebase_mutation_mapping::PushrebaseMutationMapping;
use repo_blobstore::RepoBlobstore;
use repo_blobstore::RepoBlobstoreRef;
use repo_bookmark_attrs::RepoBookmarkAttrs;
use repo_cross_repo::RepoCrossRepo;
use repo_derived_data::RepoDerivedData;
use repo_identity::RepoIdentity;
use repo_identity::RepoIdentityRef;
use repo_update_logger::BookmarkInfo;
use repo_update_logger::BookmarkOperation;
use repo_update_logger::CommitInfo;
use repo_update_logger::find_draft_ancestors;
use repo_update_logger::log_bookmark_operation;
use repo_update_logger::log_new_commits;
use scuba_ext::MononokeScubaSampleBuilder;
use sql_ext::Transaction;
use sql_ext::TransactionResult;
use sql_query_config::SqlQueryConfig;
use thiserror::Error;
use tracing::debug;
use tracing::error;
use tracing::info;
use tracing::warn;
use wireproto_handler::TargetRepoDbs;

const BOOKMARK_DISCOVERY_PAGE_SIZE_JUST_KNOB: &str =
    "scm/mononoke:backsyncer_bookmark_discovery_page_size";
const MAX_DISCOVERED_BOOKMARKS_JUST_KNOB: &str = "scm/mononoke:backsyncer_max_discovered_bookmarks";

#[derive(Clone)]
#[facet::container]
pub struct Repo(
    dyn BonsaiHgMapping,
    dyn BonsaiGitMapping,
    dyn BonsaiGlobalrevMapping,
    dyn PushrebaseMutationMapping,
    RepoCrossRepo,
    RepoBookmarkAttrs,
    dyn Bookmarks,
    SqlBookmarks,
    dyn BookmarkUpdateLog,
    FilestoreConfig,
    dyn MutableCounters,
    dyn Phases,
    RepoBlobstore,
    RepoConfig,
    RepoDerivedData,
    RepoIdentity,
    CommitGraph,
    dyn CommitGraphWriter,
    dyn Filenodes,
    SqlQueryConfig,
    dyn GitSourceOfTruthConfig,
);

#[cfg(test)]
mod tests;

#[derive(Debug, Error)]
pub enum BacksyncError {
    #[error("BacksyncError::LogEntryNotFound: {latest_log_id} not found")]
    LogEntryNotFound { latest_log_id: u64 },
    #[error("BacksyncError::Other")]
    Other(#[from] Error),
}

#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub enum BacksyncLimit {
    NoLimit,
    Limit(u64),
}

#[derive(Debug, Clone)]
pub struct BacksyncDelayInfo {
    pub delay_secs: i64,
    pub remaining_entries: u64,
    /// Bookmark workers whose backlog could not be measured because they failed.
    pub failed_bookmarks: u64,
}

/// Block until a specific bookmark transaction (identified by its log id) is confirmed to be
/// backsynced.
///
/// The backsyncer tw jobs are responsible for backsyncing bookmark transactions.
/// When they do, they update a mutable counter to the id found in the bookmark update log for this
/// transaction.
/// Wait until the mutable counters indicate that backyncing caught up.
///
/// Note that we use some form of exponential backoff to avoid causing a thundering herd problem on
/// reading the mutable counters if the backsync is lagging
///
/// We also use a hard-coded timeout to avoid being stuck forever waiting for the backsync if it is
/// lagging. Not having this timeout has caused SEVs in the past, blocking lands.
pub async fn ensure_backsynced<R>(
    ctx: CoreContext,
    commit_sync_data: CommitSyncData<R>,
    target_repo_dbs: Arc<TargetRepoDbs>,
    log_id: BookmarkUpdateLogId,
) -> Result<(), Error>
where
    R: RepoLike + Send + Sync + Clone + 'static,
{
    let timeout = Duration::from_secs(justknobs::get_as::<u64>(
        "scm/mononoke:defer_to_backsyncer_for_backsync_timeout_seconds",
        None,
    ));

    let source_repo_id = commit_sync_data.get_source_repo().repo_identity().id();
    let counter_name = format_counter(&source_repo_id);
    let start_instant = Instant::now();

    let mut sleep_times = once(1)
        .chain(once(2))
        .chain(once(5))
        .chain(repeat(10))
        .map(Duration::from_secs);
    while start_instant.elapsed() < timeout {
        let counter: BookmarkUpdateLogId = target_repo_dbs
            .counters
            .get_counter(&ctx, &counter_name)
            .await?
            .unwrap_or(0)
            .try_into()?;
        if counter >= log_id {
            return Ok(());
        }
        tokio::time::sleep(
            sleep_times
                .next()
                .expect("sleep_times is an unbounded iterator"),
        )
        .await;
    }
    bail!("Timeout expired while waiting for backsyncing")
}

pub async fn backsync_latest<R>(
    ctx: CoreContext,
    commit_sync_data: CommitSyncData<R>,
    target_repo_dbs: Arc<TargetRepoDbs>,
    limit: BacksyncLimit,
    cancellation_requested: Arc<AtomicBool>,
    sync_context: CommitSyncContext,
    disable_lease: bool,
    commit_only_backsync_future: Box<dyn Future<Output = ()> + Send + Unpin>,
) -> Result<
    (
        BacksyncDelayInfo,
        Box<dyn Future<Output = ()> + Send + Unpin>,
    ),
    Error,
>
where
    R: RepoLike + Send + Sync + Clone + 'static,
{
    // TODO(ikostia): start borrowing `CommitSyncData`, no reason to consume it
    let large_repo_id = commit_sync_data.get_source_repo().repo_identity().id();
    let counter_name = format_counter(&large_repo_id);

    let counter: BookmarkUpdateLogId = target_repo_dbs
        .counters
        .get_counter(&ctx, &counter_name)
        .await?
        .unwrap_or(0)
        .try_into()?;

    debug!("fetched counter {}", &counter);

    let log_entries_limit = match limit {
        BacksyncLimit::Limit(limit) => limit,
        BacksyncLimit::NoLimit => {
            // Set limit extremely high to read all new values
            u64::MAX
        }
    };
    let next_entries: Vec<_> = commit_sync_data
        .get_source_repo()
        .bookmark_update_log()
        .read_next_bookmark_log_entries(
            ctx.clone(),
            counter,
            log_entries_limit,
            Freshness::MostRecent,
        )
        .boxed()
        .try_collect()
        .await?;

    let delay_info = BacksyncDelayInfo {
        delay_secs: next_entries
            .first()
            .map_or(0, |entry| entry.timestamp.since_seconds()),
        remaining_entries: next_entries.len() as u64,
        failed_bookmarks: 0,
    };

    // Before syncing entries, check if cancellation has been
    // requested. If yes, then exit early.
    if cancellation_requested.load(Ordering::Relaxed) {
        info!("sync stopping due to cancellation request");
        return Ok((delay_info, commit_only_backsync_future));
    }

    if next_entries.is_empty() {
        debug!("nothing to sync");
        Ok((delay_info, commit_only_backsync_future))
    } else {
        let future = sync_entries(
            ctx,
            &commit_sync_data,
            target_repo_dbs,
            next_entries,
            counter,
            &counter_name,
            None,
            cancellation_requested,
            sync_context,
            disable_lease,
            commit_only_backsync_future,
        )
        .boxed()
        .await?;
        Ok((delay_info, future))
    }
}

async fn get_bookmark_counter_or_initialize<R>(
    ctx: &CoreContext,
    commit_sync_data: &CommitSyncData<R>,
    target_repo_dbs: &TargetRepoDbs,
    bookmark: &BookmarkKey,
    initial_counter: BookmarkUpdateLogId,
) -> Result<Option<(String, BookmarkUpdateLogId)>, Error>
where
    R: RepoLike + Send + Sync + Clone + 'static,
{
    let source_repo_id = commit_sync_data.get_source_repo().repo_identity().id();
    let initial_counter_value: i64 = initial_counter.try_into()?;
    let counter_name = format_bookmark_counter(&source_repo_id, bookmark)?;
    let Some(counter) = target_repo_dbs
        .counters
        .get_counter(ctx, &counter_name)
        .await?
    else {
        let inserted = target_repo_dbs
            .counters
            .set_counter_if_absent(ctx, &counter_name, initial_counter_value)
            .await?;
        return Ok(inserted.then_some((counter_name, initial_counter)));
    };

    // Once present, the per-bookmark cursor is authoritative. If prefix
    // polling is re-enabled after a JustKnob rollback, this cursor can lag the
    // global cursor and must catch up its bookmark rows one by one.
    Ok(Some((counter_name, counter.try_into()?)))
}

/// Backsync all outstanding log entries for one bookmark.
///
/// A new per-bookmark cursor starts at the legacy global cursor. The
/// insert-if-absent operation is atomic, so replicas racing to observe a new
/// bookmark agree on the same durable cursor before processing it.
///
/// If prefix polling is re-enabled after a JustKnob rollback, an existing
/// bookmark cursor can lag the legacy global cursor. It deliberately reads
/// those bookmark rows again; reconciliation below recognizes rows already
/// committed by the global worker and advances the bookmark cursor one exact
/// entry at a time.
pub async fn backsync_latest_for_bookmark<R>(
    ctx: CoreContext,
    commit_sync_data: CommitSyncData<R>,
    target_repo_dbs: Arc<TargetRepoDbs>,
    bookmark: BookmarkKey,
    limit: BacksyncLimit,
    cancellation_requested: Arc<AtomicBool>,
    sync_context: CommitSyncContext,
    disable_lease: bool,
) -> Result<BacksyncDelayInfo, Error>
where
    R: RepoLike + Send + Sync + Clone + 'static,
{
    let source_repo_id = commit_sync_data.get_source_repo().repo_identity().id();
    let global_counter_snapshot = target_repo_dbs
        .counters
        .get_counter(&ctx, &format_counter(&source_repo_id))
        .await?
        .unwrap_or(0)
        .try_into()?;
    backsync_bookmark_through(
        ctx,
        commit_sync_data,
        target_repo_dbs,
        bookmark,
        global_counter_snapshot,
        limit,
        cancellation_requested,
        sync_context,
        disable_lease,
    )
    .await
}

async fn backsync_bookmark_through<R>(
    ctx: CoreContext,
    commit_sync_data: CommitSyncData<R>,
    target_repo_dbs: Arc<TargetRepoDbs>,
    bookmark: BookmarkKey,
    global_counter_snapshot: BookmarkUpdateLogId,
    limit: BacksyncLimit,
    cancellation_requested: Arc<AtomicBool>,
    sync_context: CommitSyncContext,
    disable_lease: bool,
) -> Result<BacksyncDelayInfo, Error>
where
    R: RepoLike + Send + Sync + Clone + 'static,
{
    let Some((counter_name, counter)) = get_bookmark_counter_or_initialize(
        &ctx,
        &commit_sync_data,
        target_repo_dbs.as_ref(),
        &bookmark,
        global_counter_snapshot,
    )
    .await?
    else {
        // Another replica won the initialization CAS. Do not re-read and
        // proceed here: that would make the losing replica compete with the
        // winner on this bookmark. `remaining_entries: 1` is deliberately an
        // immediate-retry sentinel, not a measured backlog; the next polling
        // iteration reads the durable cursor written by the winner.
        return Ok(BacksyncDelayInfo {
            delay_secs: 0,
            remaining_entries: 1,
            failed_bookmarks: 0,
        });
    };

    let log_entries_limit = match limit {
        BacksyncLimit::Limit(limit) => limit,
        BacksyncLimit::NoLimit => u64::MAX,
    };
    let entries: Vec<_> = commit_sync_data
        .get_source_repo()
        .bookmark_update_log()
        .read_next_bookmark_log_entries_by_bookmark(
            ctx.clone(),
            bookmark,
            counter,
            log_entries_limit,
            Freshness::MostRecent,
        )
        .boxed()
        .try_collect()
        .await?;
    let delay_info = BacksyncDelayInfo {
        delay_secs: entries
            .first()
            .map_or(0, |entry| entry.timestamp.since_seconds()),
        remaining_entries: entries.len() as u64,
        failed_bookmarks: 0,
    };
    if cancellation_requested.load(Ordering::Relaxed) {
        return Ok(delay_info);
    }

    if !entries.is_empty() {
        sync_entries(
            ctx.clone(),
            &commit_sync_data,
            target_repo_dbs.clone(),
            entries,
            counter,
            &counter_name,
            Some(global_counter_snapshot),
            Arc::clone(&cancellation_requested),
            sync_context,
            disable_lease,
            Box::new(future::ready(())),
        )
        .await?
        .await;
    }

    Ok(delay_info)
}

/// Discover source bookmark keys whose exact update-log streams can affect the
/// target repository.
///
/// Current source bookmarks find creates and moves. Configured common bookmarks
/// are always included because they live outside the prefix.
async fn discover_backsync_bookmarks<R>(
    ctx: &CoreContext,
    commit_sync_data: &CommitSyncData<R>,
    bookmark_prefix: &BookmarkPrefix,
    common_bookmarks: &[BookmarkKey],
) -> Result<HashSet<BookmarkKey>, Error>
where
    R: RepoLike + Send + Sync + Clone + 'static,
{
    let bookmark_discovery_page_size = justknobs::get(BOOKMARK_DISCOVERY_PAGE_SIZE_JUST_KNOB, None);
    if bookmark_discovery_page_size <= 0 {
        bail!("{BOOKMARK_DISCOVERY_PAGE_SIZE_JUST_KNOB} must be positive");
    }
    let bookmark_discovery_page_size = bookmark_discovery_page_size.try_into()?;
    let max_discovered_bookmarks = justknobs::get(MAX_DISCOVERED_BOOKMARKS_JUST_KNOB, None);
    if max_discovered_bookmarks <= 0 {
        bail!("{MAX_DISCOVERED_BOOKMARKS_JUST_KNOB} must be positive");
    }
    let max_discovered_bookmarks = max_discovered_bookmarks.try_into()?;

    let mut bookmarks = common_bookmarks.iter().cloned().collect::<HashSet<_>>();
    let mut discovered_bookmarks = 0;

    // Pagination is name-only, so list each category separately. This avoids
    // skipping another category with the same name at a page boundary.
    for category in BookmarkCategory::ALL {
        let mut pagination = BookmarkPagination::FromStart;
        loop {
            let source_bookmarks = commit_sync_data
                .get_source_repo()
                .bookmarks()
                .list(
                    ctx.clone(),
                    Freshness::MostRecent,
                    bookmark_prefix,
                    std::slice::from_ref(category),
                    BookmarkKind::ALL_PUBLISHING,
                    &pagination,
                    bookmark_discovery_page_size,
                )
                .try_collect::<Vec<_>>()
                .await?;
            let page_len = source_bookmarks.len();
            discovered_bookmarks += page_len;
            if discovered_bookmarks > max_discovered_bookmarks {
                warn!(
                    "bookmark prefix {:?} matched {} publishing bookmarks, exceeding {} configured by {}",
                    bookmark_prefix,
                    discovered_bookmarks,
                    max_discovered_bookmarks,
                    MAX_DISCOVERED_BOOKMARKS_JUST_KNOB,
                );
                bail!(
                    "bookmark prefix {bookmark_prefix:?} matched more than {max_discovered_bookmarks} publishing bookmarks",
                );
            }
            let next_page = source_bookmarks
                .last()
                .map(|(bookmark, _)| BookmarkPagination::After(bookmark.name().clone()));
            bookmarks.extend(
                source_bookmarks
                    .into_iter()
                    .map(|(bookmark, _)| bookmark.into_key()),
            );

            if page_len < bookmark_discovery_page_size as usize {
                break;
            }
            pagination = next_page.ok_or_else(|| {
                format_err!("full bookmark discovery page did not contain a final bookmark")
            })?;
        }
    }

    Ok(bookmarks)
}

/// Backsync the source bookmark-log entries relevant to one small repository.
///
/// The configured prefix and common bookmarks form a single logical source-log
/// selector. Current source bookmarks and configured common bookmarks are
/// unioned in memory, then each candidate reads forward from its own durable
/// cursor. The legacy global cursor is only an initialization and fallback
/// boundary; this path does not advance it.
pub async fn backsync_latest_by_prefix<R>(
    ctx: CoreContext,
    commit_sync_data: CommitSyncData<R>,
    target_repo_dbs: Arc<TargetRepoDbs>,
    bookmark_prefix: BookmarkPrefix,
    common_bookmarks: &[BookmarkKey],
    limit: BacksyncLimit,
    bookmark_concurrency: usize,
    cancellation_requested: Arc<AtomicBool>,
    sync_context: CommitSyncContext,
    disable_lease: bool,
) -> Result<BacksyncDelayInfo, Error>
where
    R: RepoLike + Send + Sync + Clone + 'static,
{
    let source_repo_id = commit_sync_data.get_source_repo().repo_identity().id();
    let global_counter_name = format_counter(&source_repo_id);
    let global_counter: BookmarkUpdateLogId = target_repo_dbs
        .counters
        .get_counter(&ctx, &global_counter_name)
        .await?
        .unwrap_or(0)
        .try_into()?;

    let bookmarks =
        discover_backsync_bookmarks(&ctx, &commit_sync_data, &bookmark_prefix, common_bookmarks)
            .await?;

    let progress = stream::iter(bookmarks)
        .map(|bookmark| {
            cloned!(
                ctx,
                commit_sync_data,
                target_repo_dbs,
                cancellation_requested
            );
            async move {
                let result = backsync_bookmark_through(
                    ctx,
                    commit_sync_data,
                    target_repo_dbs,
                    bookmark.clone(),
                    global_counter,
                    limit,
                    cancellation_requested,
                    sync_context,
                    disable_lease,
                )
                .await;
                (bookmark, result)
            }
        })
        .buffer_unordered(bookmark_concurrency.max(1))
        .collect::<Vec<_>>()
        .await;

    let mut delay_info = BacksyncDelayInfo {
        delay_secs: 0,
        remaining_entries: 0,
        failed_bookmarks: 0,
    };
    for (bookmark, result) in progress {
        match result {
            Ok(bookmark_delay) => {
                delay_info.delay_secs = delay_info.delay_secs.max(bookmark_delay.delay_secs);
                delay_info.remaining_entries += bookmark_delay.remaining_entries;
            }
            Err(error) => {
                // One bad bookmark must not cancel successful in-flight work or
                // terminate the repo-pair loop. Its durable cursor is unchanged,
                // so the next polling iteration retries it.
                error!("Failed to backsync bookmark {:?}: {:#}", bookmark, error);
                // Keep `remaining_entries` limited to measured backlog rather
                // than inventing a count for a worker that returned no result.
                delay_info.failed_bookmarks += 1;
            }
        }
    }

    Ok(delay_info)
}

async fn sync_entries<R>(
    mut ctx: CoreContext,
    commit_sync_data: &CommitSyncData<R>,
    target_repo_dbs: Arc<TargetRepoDbs>,
    entries: Vec<BookmarkUpdateLogEntry>,
    mut counter: BookmarkUpdateLogId,
    counter_name: &str,
    global_counter_snapshot: Option<BookmarkUpdateLogId>,
    cancellation_requested: Arc<AtomicBool>,
    sync_context: CommitSyncContext,
    disable_lease: bool,
    mut commit_only_backsync_future: Box<dyn Future<Output = ()> + Send + Unpin>,
) -> Result<Box<dyn Future<Output = ()> + Send + Unpin>, Error>
where
    R: RepoLike + Send + Sync + Clone + 'static,
{
    for entry in entries {
        // Before processing each entry, check if cancellation has
        // been requested and exit if that's the case.
        if cancellation_requested.load(Ordering::Relaxed) {
            info!("sync stopping due to cancellation request");
            return Ok(commit_only_backsync_future);
        }
        // A cursor only advances after this execution model has acknowledged
        // the corresponding row. If a competing replica moved it beyond the
        // entry, that replica also completed all preceding rows in this same
        // ordered stream.
        if counter >= entry.id {
            continue;
        }
        // Reconcile legacy completion before attempting the bookmark
        // transaction. This keeps transaction-conflict handling independent:
        // a genuine conflict below still returns an error rather than being
        // reclassified after the fact.
        if advance_bookmark_counter_for_completed_global(
            &ctx,
            target_repo_dbs.as_ref(),
            &entry,
            &mut counter,
            counter_name,
            global_counter_snapshot,
        )
        .await?
        {
            continue;
        }
        if advance_global_counter_for_completed_bookmark(
            &ctx,
            commit_sync_data,
            target_repo_dbs.as_ref(),
            &entry,
            &mut counter,
            counter_name,
        )
        .await?
        {
            continue;
        }
        let mut scuba_sample = ctx.scuba().clone();
        let pc = ctx.fork_perf_counters();
        let mut scuba_log_tag = "Backsyncing".to_string();
        let (stats, new_commit_only_backsync_future) = do_sync_entry(
            ctx.clone(),
            commit_sync_data,
            &target_repo_dbs,
            entry,
            &mut counter,
            counter_name,
            sync_context,
            disable_lease,
            commit_only_backsync_future,
            &mut scuba_sample,
            &mut scuba_log_tag,
        )
        .try_timed()
        .await?;
        commit_only_backsync_future = new_commit_only_backsync_future;
        pc.insert_perf_counters(&mut scuba_sample);
        scuba_sample
            .add_future_stats(&stats)
            .log_with_msg(&scuba_log_tag, None);
    }
    Ok(commit_only_backsync_future)
}

/// Let a per-bookmark worker acknowledge an entry already completed by the
/// legacy globally ordered worker after a JustKnob rollback and re-enablement.
///
/// The global cursor proves every source-log row through its value completed.
/// We still advance the bookmark cursor one exact row at a time so no bookmark
/// update is skipped when returning to per-bookmark polling.
async fn advance_bookmark_counter_for_completed_global(
    ctx: &CoreContext,
    target_repo_dbs: &TargetRepoDbs,
    entry: &BookmarkUpdateLogEntry,
    counter: &mut BookmarkUpdateLogId,
    counter_name: &str,
    global_counter_snapshot: Option<BookmarkUpdateLogId>,
) -> Result<bool, Error> {
    let Some(global_counter) = global_counter_snapshot else {
        return Ok(false);
    };
    if global_counter < entry.id {
        return Ok(false);
    }

    while *counter < entry.id {
        if target_repo_dbs
            .counters
            .set_counter(
                ctx,
                counter_name,
                entry.id.try_into()?,
                Some((*counter).try_into()?),
            )
            .await?
        {
            *counter = entry.id;
            break;
        }

        let observed: BookmarkUpdateLogId = target_repo_dbs
            .counters
            .get_counter(ctx, counter_name)
            .await?
            .unwrap_or(0)
            .try_into()?;
        if observed <= *counter {
            return Err(format_err!(
                "failed to reconcile bookmark cursor through globally completed entry {}; observed {}",
                entry.id,
                observed,
            ));
        }
        *counter = observed;
    }

    debug!(
        "legacy global cursor {} already covered {}; advanced bookmark cursor without replaying",
        global_counter, entry.id
    );
    Ok(true)
}

/// Let the legacy global loop acknowledge an entry already committed by the
/// per-bookmark path. This is what makes a JustKnob rollback safe after only a
/// subset of the parallel bookmark workers completed.
///
/// `sync_entries` invokes this for the globally ordered log entries one at a
/// time. Advancing to `entry.id` therefore acknowledges only the current row;
/// every earlier row for this repository has already been handled. Numeric ID
/// gaps can belong to other repositories because the database sequence is
/// shared.
///
/// A per-bookmark cursor is the same completion boundary used by the normal
/// worker: mapped bookmarks advance it only after commit sync and the atomic
/// bookmark/counter transaction complete. For an unmapped bookmark it records
/// the legacy best-effort commit-only behavior after that task is scheduled.
async fn advance_global_counter_for_completed_bookmark<R>(
    ctx: &CoreContext,
    commit_sync_data: &CommitSyncData<R>,
    target_repo_dbs: &TargetRepoDbs,
    entry: &BookmarkUpdateLogEntry,
    counter: &mut BookmarkUpdateLogId,
    counter_name: &str,
) -> Result<bool, Error>
where
    R: RepoLike + Send + Sync + Clone + 'static,
{
    let source_repo_id = commit_sync_data.get_source_repo().repo_identity().id();
    let global_counter_name = format_counter(&source_repo_id);
    if counter_name != global_counter_name {
        return Ok(false);
    }

    let bookmark_counter_name = format_bookmark_counter(&source_repo_id, &entry.bookmark_name)?;
    let bookmark_counter: BookmarkUpdateLogId = match target_repo_dbs
        .counters
        .get_counter(ctx, &bookmark_counter_name)
        .await?
    {
        Some(bookmark_counter) => bookmark_counter.try_into()?,
        None => return Ok(false),
    };
    if bookmark_counter < entry.id {
        return Ok(false);
    }

    while *counter < entry.id {
        if target_repo_dbs
            .counters
            .set_counter(
                ctx,
                &global_counter_name,
                entry.id.try_into()?,
                Some((*counter).try_into()?),
            )
            .await?
        {
            *counter = entry.id;
            break;
        }

        let observed: BookmarkUpdateLogId = target_repo_dbs
            .counters
            .get_counter(ctx, &global_counter_name)
            .await?
            .unwrap_or(0)
            .try_into()?;
        if observed <= *counter {
            return Err(format_err!(
                "failed to advance global backsync cursor past bookmark entry {}; observed {}",
                entry.id,
                observed,
            ));
        }
        if observed > entry.id {
            debug!(
                "global backsync cursor advanced concurrently past {} to {}; another legacy worker completed the intervening ordered entries",
                entry.id, observed
            );
        }
        *counter = observed;
    }

    debug!(
        "bookmark cursor already covered {}; advanced legacy cursor without replaying",
        entry.id
    );
    Ok(true)
}

// This function is the inner function for sync_entries and shouldn't be called by other callers.
// It encapsulates of what we consider as doing a single "backsyncing" for bookmark entry: an
// activity that we want to time and log.
async fn do_sync_entry<R>(
    ctx: CoreContext,
    commit_sync_data: &CommitSyncData<R>,
    target_repo_dbs: &Arc<TargetRepoDbs>,
    entry: BookmarkUpdateLogEntry,
    counter: &mut BookmarkUpdateLogId,
    counter_name: &str,
    sync_context: CommitSyncContext,
    disable_lease: bool,
    mut commit_only_backsync_future: Box<dyn Future<Output = ()> + Send + Unpin>,
    scuba_sample: &mut MononokeScubaSampleBuilder,
    scuba_log_tag: &mut String,
) -> Result<Box<dyn Future<Output = ()> + Send + Unpin>, Error>
where
    R: RepoLike + Send + Sync + Clone + 'static,
{
    let entry_id = entry.id;
    if *counter >= entry_id {
        return Ok(commit_only_backsync_future);
    }
    debug!("backsyncing {} ...", entry_id);

    if commit_sync_data
        .rename_bookmark(&entry.bookmark_name)
        .await?
        .is_none()
    {
        // For the bookmarks that don't remap to small repos we can skip. But it's
        // still valuable to have commit mapping ready for them. That's why we spawn
        // a commit backsync future that we don't wait for here. Each of such futures
        // waits for result of previous commit-only backsync so we don't duplicate
        // work unnecessarily.
        debug!("Renamed bookmark is None. No sync happening.");
        target_repo_dbs
            .counters
            .set_counter(
                &ctx,
                counter_name,
                entry.id.try_into()?,
                Some((*counter).try_into()?),
            )
            .await?;
        *counter = entry.id;
        if let Some(to_cs_id) = entry.to_changeset_id {
            commit_only_backsync_future = Box::new({
                cloned!(ctx, sync_context, to_cs_id, commit_sync_data);
                mononoke::spawn_task(async move {
                    commit_only_backsync_future.await;
                    let res = sync_commit(
                        &ctx,
                        to_cs_id.clone(),
                        &commit_sync_data,
                        // Backsyncer is always used in the large-to-small direction,
                        // therefore there can be at most one remapped candidate,
                        // so `CandidateSelectionHint::Only` is a safe choice
                        CandidateSelectionHint::Only,
                        sync_context,
                        disable_lease,
                    )
                    .await;
                    if let Err(err) = res {
                        error!(
                            "Failed to backsync {} pointing to {}: {}",
                            entry.bookmark_name, to_cs_id, err
                        );
                    }
                })
                .map(|_| ())
            });
        }

        return Ok(commit_only_backsync_future);
    }

    scuba_sample.add("backsyncer_bookmark_log_entry_id", u64::from(entry.id));

    let start_instant = Instant::now();

    if let Some(to_cs_id) = entry.to_changeset_id {
        let (_, unsynced_ancestors_versions) =
            find_toposorted_unsynced_ancestors(&ctx, commit_sync_data, to_cs_id, None).await?;

        if !unsynced_ancestors_versions.has_ancestor_with_a_known_outcome() {
            // Not a single ancestor of to_cs_id was ever synced.
            // That means that we can't figure out which commit sync mapping version
            // to use. In that case we just skip this entry and not sync it at all.
            // This seems the safest option (i.e. we won't rewrite a commit with
            // an incorrect version) but it also has a downside that the bookmark that points
            // to this commit is not going to be synced.
            warn!("skipping {}, entry id {}", entry.bookmark_name, entry.id);
            *scuba_log_tag = "Skipping entry because there are no synced ancestors".to_string();
            target_repo_dbs
                .counters
                .set_counter(
                    &ctx,
                    counter_name,
                    entry.id.try_into()?,
                    Some((*counter).try_into()?),
                )
                .await?;
            *counter = entry.id;
            return Ok(commit_only_backsync_future);
        }

        // Backsyncer is always used in the large-to-small direction,
        // therefore there can be at most one remapped candidate,
        // so `CandidateSelectionHint::Only` is a safe choice

        sync_commit(
            &ctx,
            to_cs_id,
            commit_sync_data,
            CandidateSelectionHint::Only,
            sync_context,
            disable_lease,
        )
        .await?;
    }

    let new_counter = entry.id;
    let maybe_log_id = backsync_bookmark(
        ctx.clone(),
        commit_sync_data,
        target_repo_dbs.clone(),
        Some(*counter),
        counter_name,
        &entry,
    )
    .await?;
    scuba_sample.add_opt(
        "from_csid",
        entry.from_changeset_id.map(|csid| csid.to_string()),
    );
    scuba_sample.add_opt(
        "to_csid",
        entry.to_changeset_id.map(|csid| csid.to_string()),
    );
    scuba_sample.add(
        "backsync_duration_ms",
        u64::try_from(start_instant.elapsed().as_millis()).unwrap_or(u64::MAX),
    );
    scuba_sample.add("backsync_previously_done", maybe_log_id.is_none());

    if let Some(_log_id) = maybe_log_id {
        *counter = new_counter;
    } else {
        debug!(
            "failed to backsync {}, most likely another process already synced it ",
            entry_id
        );
        // Transaction failed, it could be because another process already backsynced it
        // Verify that counter was moved and continue if that's the case

        let observed_counter: BookmarkUpdateLogId = target_repo_dbs
            .counters
            .get_counter(&ctx, counter_name)
            .await?
            .unwrap_or(0)
            .try_into()?;
        if observed_counter <= *counter {
            return Err(format_err!(
                "backsync transaction failed, but the counter didn't move forward. Was {}, became {}",
                *counter,
                observed_counter,
            ));
        } else {
            debug!(
                "verified that another process has already synced {}",
                entry_id
            );
            *counter = observed_counter;
        }
    }
    Ok(commit_only_backsync_future)
}

/// All "new" commits on this bookmark move. Use with care, creating a bookmark
/// means ALL ancestors are new.
async fn commits_added_by_bookmark_move(
    ctx: &CoreContext,
    repo: &impl RepoLike,
    from_cs_id: Option<ChangesetId>,
    to_cs_id: Option<ChangesetId>,
) -> Result<HashSet<ChangesetId>, Error> {
    match (from_cs_id, to_cs_id) {
        (_, None) => Ok(HashSet::new()),
        (None, Some(to_id)) => {
            repo.commit_graph()
                .ancestors_difference_stream(ctx, vec![to_id], vec![])
                .await?
                .try_collect()
                .await
        }
        (Some(from_id), Some(to_id)) => {
            // If needed, this can be optimised by using range_stream when from_id is
            // an ancestor of from_id
            repo.commit_graph()
                .ancestors_difference_stream(ctx, vec![to_id], vec![from_id])
                .await?
                .try_collect()
                .await
        }
    }
}

async fn backsync_bookmark<R>(
    ctx: CoreContext,
    commit_sync_data: &CommitSyncData<R>,
    target_repo_dbs: Arc<TargetRepoDbs>,
    prev_counter: Option<BookmarkUpdateLogId>,
    counter_name: &str,
    log_entry: &BookmarkUpdateLogEntry,
) -> Result<Option<BookmarkUpdateLogId>, Error>
where
    R: RepoLike + Send + Sync + Clone + 'static,
{
    let prev_counter: Option<i64> = prev_counter.map(|x| x.try_into()).transpose()?;
    let target_repo_id = commit_sync_data.get_target_repo().repo_identity().id();
    let counter_name = counter_name.to_owned();
    debug!("preparing to backsync {:?}", log_entry);

    let new_counter = log_entry.id;
    let bookmark = commit_sync_data
        .rename_bookmark(&log_entry.bookmark_name)
        .await?;
    debug!("bookmark was renamed into {:?}", bookmark);
    let from_cs_id = log_entry.from_changeset_id;
    let to_cs_id = log_entry.to_changeset_id;

    let get_commit_sync_outcome = |maybe_cs_id: Option<ChangesetId>| {
        cloned!(ctx);
        async move {
            match maybe_cs_id {
                Some(cs_id) => {
                    let maybe_outcome = commit_sync_data
                        .get_commit_sync_outcome(&ctx, cs_id)
                        .await?;
                    match maybe_outcome {
                        Some(outcome) => Ok(Some((outcome, cs_id))),
                        None => Err(format_err!("{cs_id} hasn't been backsynced yet")),
                    }
                }
                None => Ok(None),
            }
        }
    };

    let get_remapped_cs_id =
        move |maybe_outcome: Option<(CommitSyncOutcome, ChangesetId)>| match maybe_outcome {
            Some((outcome, cs_id)) => {
                use CommitSyncOutcome::*;
                match outcome {
                    NotSyncCandidate(_) => Err(format_err!(
                        "invalid bookmark move: {cs_id:?} should not be synced to target repo"
                    )),
                    RewrittenAs(cs_id, _) | EquivalentWorkingCopyAncestor(cs_id, _) => {
                        Ok(Some(cs_id))
                    }
                }
            }
            None => Ok(None),
        };

    if let Some(bookmark) = bookmark {
        // Fetch sync outcome before transaction to keep transaction as short as possible
        let from_sync_outcome = get_commit_sync_outcome(from_cs_id).await?;
        let to_sync_outcome = get_commit_sync_outcome(to_cs_id).await?;
        debug!(
            "commit sync outcomes: from_cs: {:?}, to_cs: {:?}",
            from_sync_outcome, to_sync_outcome
        );

        let from_cs_id = get_remapped_cs_id(from_sync_outcome)?;
        let to_cs_id = get_remapped_cs_id(to_sync_outcome)?;
        let bookmark_info = BookmarkInfo {
            bookmark_name: bookmark.clone(),
            bookmark_kind: BookmarkKind::Publishing, // Only publishing bookmarks are back synced
            operation: BookmarkOperation::new(from_cs_id, to_cs_id)?,
            reason: BookmarkUpdateReason::Backsyncer,
        };

        if from_cs_id != to_cs_id {
            let target_repo = commit_sync_data.get_target_repo();
            // This CANNOT be done after getting the bookmark transaction, because it accesses SQL without a
            // transaction and that causes a deadlock that blocks the syncing.
            let globalrev_entries: Vec<BonsaiGlobalrevMappingEntry> = if target_repo
                .repo_config()
                .pushrebase
                .globalrev_config
                .as_ref()
                .map(|c| &c.publishing_bookmark)
                == Some(&bookmark)
            {
                let all_commits =
                    commits_added_by_bookmark_move(&ctx, target_repo, from_cs_id, to_cs_id).await?;
                let ctx = &ctx;
                let blobstore = target_repo.repo_blobstore();
                stream::iter(all_commits)
                    .map(|bcs_id| async move {
                        let cs = bcs_id.load(ctx, blobstore).await?;
                        // When pushrebasing into the large repo, this commit
                        // should've gotten a globalrev
                        // But if it doesn't it's better to skip assigning the globalrev
                        // than to break the backsync process. (The commit was already acknowledged
                        // and we have not much choice on whether to sync it).
                        let globalrev = Globalrev::from_bcs(&cs).ok();
                        if let Some(globalrev) = globalrev {
                            anyhow::Ok(Some(BonsaiGlobalrevMappingEntry { bcs_id, globalrev }))
                        } else {
                            anyhow::Ok(None)
                        }
                    })
                    .buffer_unordered(100)
                    .try_filter_map(|res| future::ready(Ok(res)))
                    .try_collect()
                    .await?
            } else {
                vec![]
            };
            let commits_to_log = async {
                match to_cs_id {
                    Some(to_cs_id) => {
                        let res = find_draft_ancestors(&ctx, target_repo, to_cs_id).await;
                        match res {
                            Ok(bcss) => bcss.iter().map(|bcs| CommitInfo::new(bcs, None)).collect(),
                            Err(err) => {
                                ctx.scuba().clone().log_with_msg(
                                    "Failed to find draft ancestors for logging",
                                    Some(format!("{err}")),
                                );
                                vec![]
                            }
                        }
                    }
                    None => vec![],
                }
            }
            .await;

            let mut bookmark_txn = target_repo_dbs.bookmarks.create_transaction(ctx.clone());
            debug!("syncing bookmark {} to {:?}", bookmark, to_cs_id);

            match (from_cs_id, to_cs_id) {
                (Some(from), Some(to)) => {
                    debug!(
                        "updating bookmark {:?} from {:?} to {:?}",
                        bookmark, from, to
                    );
                    bookmark_txn.update(&bookmark, to, from, BookmarkUpdateReason::Backsyncer)?;
                }
                (Some(from), None) => {
                    debug!(
                        "deleting bookmark {:?} with original position {:?}",
                        bookmark, from
                    );
                    bookmark_txn.delete(&bookmark, from, BookmarkUpdateReason::Backsyncer)?;
                }
                (None, Some(to)) => {
                    debug!("creating bookmark {:?} to point to {:?}", bookmark, to);
                    bookmark_txn.create(&bookmark, to, BookmarkUpdateReason::Backsyncer)?;
                }
                (None, None) => {
                    bail!("unexpected bookmark move");
                }
            };
            let new_counter = new_counter.try_into()?;
            let counter_name_for_txn = counter_name.clone();

            let txn_hook = Arc::new({
                move |ctx: CoreContext, txn: Transaction| {
                    cloned!(counter_name_for_txn, globalrev_entries);
                    async move {
                        // This is an abstraction leak: it only works because the
                        // mutable counters/globalrevs are stored in the same db as the
                        // bookmarks.
                        let txn_result = SqlMutableCounters::set_counter_on_txn(
                            &ctx,
                            target_repo_id,
                            &counter_name_for_txn,
                            new_counter,
                            prev_counter,
                            txn,
                        )
                        .await?;

                        let txn = match txn_result {
                            TransactionResult::Succeeded(txn) => Ok(txn),
                            TransactionResult::Failed => Err(BookmarkTransactionError::LogicError),
                        }?;

                        if !globalrev_entries.is_empty() {
                            bonsai_globalrev_mapping::add_globalrevs(
                                &ctx,
                                txn,
                                target_repo_id,
                                &globalrev_entries,
                            )
                            .await
                            .map_err(|err| BookmarkTransactionError::Other(err.into()))
                        } else {
                            Ok(txn)
                        }
                    }
                    .boxed()
                }
            });

            let res = bookmark_txn
                .commit_with_hooks(vec![txn_hook])
                .await?
                .map(|x| x.into());
            log_new_commits(
                &ctx,
                target_repo,
                Some((&bookmark, BookmarkKind::Publishing)),
                commits_to_log,
            )
            .await;
            log_bookmark_operation(&ctx, target_repo, &bookmark_info).await;
            return Ok(res);
        } else {
            debug!(
                "from_cs_id and to_cs_id are the same: {:?}. No sync happening for {:?}",
                from_cs_id, bookmark
            );
        }
    } else {
        debug!("Renamed bookmark is None. No sync happening.");
    }

    let maybe_log_id = if target_repo_dbs
        .counters
        .set_counter(&ctx, &counter_name, new_counter.try_into()?, prev_counter)
        .await?
    {
        Some(new_counter)
    } else {
        None
    };

    Ok(maybe_log_id)
}

pub async fn open_backsyncer_dbs(repo: &impl RepoLike) -> Result<TargetRepoDbs, Error> {
    Ok(TargetRepoDbs {
        bookmarks: repo.bookmarks_arc(),
        bookmark_update_log: repo.bookmark_update_log_arc(),
        counters: repo.mutable_counters_arc(),
    })
}

pub fn format_counter(repo_to_backsync_from: &RepositoryId) -> String {
    format!("backsync_from_{}", repo_to_backsync_from.id())
}

/// Format a human-readable mutable-counter name for one source bookmark.
///
/// The source repository and bookmark category keep otherwise identical
/// bookmark names in separate cursor domains.
pub fn format_bookmark_counter(
    repo_to_backsync_from: &RepositoryId,
    bookmark: &BookmarkKey,
) -> Result<String, Error> {
    let counter_name = format!(
        "backsync_by_bookmark_v1_{}_{}_{}",
        repo_to_backsync_from.id(),
        bookmark.category(),
        bookmark.as_str(),
    );
    validate_counter_name(&counter_name)?;
    Ok(counter_name)
}
